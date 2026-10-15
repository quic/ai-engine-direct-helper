#!/usr/bin/env python3
# -*- coding: utf-8 -*-
#=============================================================================
#
# Copyright (c) 2025, Qualcomm Innovation Center, Inc. All rights reserved.
#
# SPDX-License-Identifier: BSD-3-Clause
#
#=============================================================================
"""
GenieAPIService 集成测试脚本

自动启动服务、执行全部 API 接口测试（含流式/非流式）、采集性能数据，
输出 HTML 报告 + JSON 结构化结果 + 对话记录 HTML。

用法:
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models
    python test_service.py --remote --host 10.92.140.91 --port 8910
"""

import argparse
import atexit
import base64
import collections
import copy
import hashlib
import io
import json
import os
import random
import re
import shlex
import signal
import subprocess
import sys
import threading
import time
from dataclasses import dataclass, field, asdict
from pathlib import Path
from datetime import datetime

# 强制 stdout/stderr 使用 UTF-8 编码（Windows 控制台兼容）
if sys.platform == 'win32' and getattr(sys.stdout, 'encoding', '').lower() != 'utf-8':
    # 幂等包装：若已是 utf-8(例如被 test_watermark.py 之类的脚本 import 前已包装过一次),
    # 不要重复包装,否则旧 TextIOWrapper 被 GC 时会关闭共享的底层 buffer,
    # 导致后续 print() 报 "I/O operation on closed file"。
    sys.stdout = io.TextIOWrapper(sys.stdout.buffer, encoding='utf-8', errors='replace')
    sys.stderr = io.TextIOWrapper(sys.stderr.buffer, encoding='utf-8', errors='replace')

try:
    import requests
except ImportError:
    print("ERROR: 'requests' 库未安装，请执行 pip install requests")
    sys.exit(1)

try:
    import psutil
    HAS_PSUTIL = True
except ImportError:
    HAS_PSUTIL = False
    print("WARNING: 'psutil' 未安装，性能采集将被跳过。pip install psutil")

# 逻辑核心数：用于把 psutil Process.cpu_percent() 的原始值（单核=100%，多线程/多核累加可能
# 远超 100%，例如 MNN 用满 7-8 个核心时能到 700+%）归一化为"占整机总算力的百分比"展示，
# 避免报告里出现反直觉的大数字。仅用于展示层归一化：PerfMonitor 采集/写入 results.json 的
# 原始样本值不受影响，保持向后兼容。
_LOGICAL_CPU_COUNT = (psutil.cpu_count(logical=True) or 1) if HAS_PSUTIL else 1


def _normalize_cpu_percent(raw_percent):
    """把 Process.cpu_percent() 的原始值归一化为相对整机总算力的百分比（除以逻辑核心数）。
    raw_percent 为 None/0 时原样返回，不做除法。"""
    if not raw_percent:
        return raw_percent
    return raw_percent / _LOGICAL_CPU_COUNT


# ============================================================================
# 预定义测试 Prompts（3 轮使用不同问题）
# ============================================================================
TEST_PROMPTS = [
    "What is the capital of France? Please answer in one sentence.",
    "Explain what a neural network is in simple terms.",
    "Write a short Python function that calculates the factorial of a number.",
]

# 多模态测试用的图文/图音问题
MULTIMODAL_PROMPTS = [
    "What is in this image? Please describe it briefly.",
    "Describe the main content of this image in one sentence.",
]


def detect_modality(model_name):
    """根据模型目录名前缀判断多模态能力: qwen2.5vl→图片, qwen2.5_omini→图片+音频, phi4→图片,
    qwen3_vl→图片, 其余(纯 qwen3/gpt-oss 等)→纯文本(空集合)"""
    lower = model_name.lower()
    if "qwen2.5_omini" in lower or "qwen2.5-omini" in lower:
        return {"image", "audio"}
    if "qwen2.5vl" in lower or "qwen2.5-vl" in lower:
        return {"image"}
    if "phi4" in lower:
        return {"image"}
    if "qwen3_vl" in lower or "qwen3-vl" in lower:
        return {"image"}
    return set()


def infer_backend(model_name):
    """根据模型目录名猜测其后端与设备：GGUF→(GGUF, gpu)，MNN→(mnn, cpu)，其余（QNN）→(qnn, npu)。
    MNN 与 GGUF(llama.cpp) 后端完全不支持多模态，其目录名从不匹配 detect_modality() 的前缀规则。"""
    lower = model_name.lower()
    if "gguf" in lower:
        return "GGUF", "gpu"
    if "mnn" in lower:
        return "mnn", "cpu"
    return "qnn", "npu"


_GGUF_DEVICE_NAMES = ("npu", "gpu", "cpu")


def parse_gguf_devices(value):
    """解析 --gguf_devices：逗号分隔的设备组合，每个组合用 '+' 连接多个设备（如 npu+gpu），
    取值仅 npu/gpu/cpu；'both' 等价于 gpu,cpu。返回去重后保持顺序的组合元组。"""
    if value.strip().lower() == "both":
        return ("gpu", "cpu")
    specs = []
    for item in value.split(","):
        names = [n.strip().lower() for n in item.split("+")]
        if not item.strip() or any(n not in _GGUF_DEVICE_NAMES for n in names) or len(set(names)) != len(names):
            raise argparse.ArgumentTypeError(
                f"非法的 --gguf_devices 取值 '{item}'：设备仅限 {'/'.join(_GGUF_DEVICE_NAMES)}，多设备用 '+' 连接（如 npu+gpu），多个组合用 ',' 分隔")
        spec = "+".join(names)
        if spec not in specs:
            specs.append(spec)
    return tuple(specs)


def evaluate_gguf_device_result(requested_list, actual_device, actual_effective):
    if requested_list == ["gpu"]:
        return actual_device in ("gpu", "cpu"), False, ("；GPU 加载 fallback 到 CPU" if actual_device == "cpu" else "")
    if requested_list == ["cpu"]:
        return actual_device == "cpu", False, ""
    allowed_effective = set(requested_list) | {"gpu", "cpu"}
    device_ok = (actual_device in ("gpu", "cpu") and bool(actual_effective)
                 and set(actual_effective) <= allowed_effective)
    npu_degraded = "npu" in requested_list and "npu" not in actual_effective
    fallback_note = ""
    if npu_degraded:
        fallback_note += "；npu 降级（HTP0 不可用，已去掉 npu）"
    if actual_device == "cpu" and "cpu" not in requested_list:
        fallback_note += "；GPU 加载 fallback 到 CPU"
    return device_ok, npu_degraded, fallback_note


# 纯文本 chat 请求的 3 种 content 格式，按轮次轮流使用，让回归覆盖到服务端支持的全部输入方式，
# 而不是只测最常见的一种。对应关系（详见 examples/GenieAPIClient/GenieAPIClient.cpp 与
# ModelInputBuilder::ProcessArray/ProcessObject）：
#   openai_string: content 为纯字符串——GenieAPIClient 纯文本请求（无 --img）与最基础的 OpenAI
#                  用法一致，走 ModelInputBuilder 的纯字符串分支。
#   openai_array:  content 为 [{"type":"text","text":...}] 数组——OpenAI 标准的多段 content 格式，
#                  走 ModelInputBuilder::ProcessArray（多模态用例已用此路径测图片/音频，这里补上纯文本场景）。
#   client_object: content 为 {"question": ...} 扁平对象——GenieAPIClient 风格（对应其 --img 时构造的
#                  json j; j["question"]=...; j["image"]=...），走 ModelInputBuilder::ProcessObject，
#                  这里只填 question 字段，验证该风格在纯文本(无 image/audio)场景下同样受支持。
CHAT_CONTENT_FORMATS = ("openai_string", "openai_array", "client_object")


def _build_chat_content(prompt, content_format):
    """按 content_format 构造 chat 请求 messages[].content 的值,三种格式语义见 CHAT_CONTENT_FORMATS 上方注释。"""
    if content_format == "openai_array":
        return [{"type": "text", "text": prompt}]
    if content_format == "client_object":
        return {"question": prompt}
    return prompt  # openai_string（默认，向后兼容旧行为）


SYSTEM_PROMPT = "You are a helpful assistant."


def _build_chat_system_content(content_format):
    """system 消息的 content 同样按 content_format 轮换格式,与 _build_chat_content 用途一致,
    确保 GenieRoutingGateway 等读取 system 消息 content 的代码路径也能被三种格式覆盖到
    (GenieAPIClient.exe 默认请求格式对 system/user 消息是同时恒定使用数组形式的)。"""
    return _build_chat_content(SYSTEM_PROMPT, content_format)


def _content_format_label(content_format):
    """content_format → 报告展示用的中文短标签 + CSS 修饰类名后缀。"""
    return {
        "openai_array": ("OpenAI数组风格", "array"),
        "client_object": ("GenieAPIClient对象风格", "object"),
    }.get(content_format, ("OpenAI字符串风格", "string"))


def _content_format_badge_html(r):
    """把 TestResult.request_format 渲染为报告里的小标签(复用 .mode-tag 体系,与既有的
    stream/non-stream 标签同一视觉语言)。request_format 为空(非 chat 用例)时返回空字符串。"""
    content_format = getattr(r, "request_format", "")
    if not content_format:
        return ""
    label, css_suffix = _content_format_label(content_format)
    return f' <span class="mode-tag mode-format-{css_suffix}" title="本次请求 content 字段使用的格式">{label}</span>'


# ============================================================================
# 数据结构
# ============================================================================
@dataclass
class TestResult:
    name: str
    round_num: int
    model_name: str
    passed: bool
    status_code: int
    latency_ms: float
    detail: str
    crashed: bool = False
    skipped: bool = False
    text_response: str = ""
    text_prompt: str = ""
    is_stream: bool = False
    ttft_ms: float = 0.0
    chunk_count: int = 0
    # 本次 chat 请求使用的 content 格式（见 CHAT_CONTENT_FORMATS）：openai_string(默认,向后兼容)/
    # openai_array/client_object。空字符串表示该测试不涉及 chat content 格式（如非 chat 接口）。
    request_format: str = ""
    perf_before: dict = field(default_factory=dict)
    perf_after: dict = field(default_factory=dict)
    response_data: dict = field(default_factory=dict)  # 各接口返回的结构化数据
    # 已知缺陷标记: 当 passed=False 但该失败属于"服务端已知问题、可以忽略"时,
    # 把 ignorable 置为 True 并填 ignore_reason 说明为什么可以忽略。
    # 例如: /images/generations 501 (未实现)、/reload 400 "Not supported in stateless mode"
    # (占位实现)、/status 400 "invalid json" (服务端 set_content type_error bug)。
    # 报告里这类失败仍然显示为 FAIL 但带有"可忽略"小徽章 + tooltip 说明,
    # 总计里单独再算一个 ignored 计数,便于过滤"真实失败 vs 已知缺陷"。
    ignorable: bool = False
    ignore_reason: str = ""
    # 模型能力问题标记(与 ignorable/ignore_reason 同一种成对字段设计)：该测试的结果/检测到的
    # 异常,根因判定为模型自身能力或输出质量局限而非服务端缺陷(如重复出词、tool_calls 未按
    # 指令触发、function.arguments 非合法 JSON)。与 passed/skipped/ignorable 是正交的诊断
    # 维度,不改变任何既有判定逻辑与退出码口径,只是把该结论从纯文本 detail 提升为结构化字段。
    model_capability_issue: bool = False
    model_capability_reason: str = ""
    # MNN OOM 崩溃后已自动重启服务并跳过该模型剩余轮次，不计入 failed/crashed。
    auto_restarted: bool = False
    # 多模态请求实际使用的素材(图片/音频),供 conversations.html 渲染真实内容,而不是只有
    # 一句"该模型支持图片"这类文字描述、看不到到底传了哪张图/哪段音频。存完整 data URI
    # (浏览器可直接用于 <img src=.../<audio src=...>)。这两个字段只在内存中的 TestResult
    # 对象上使用；generate_json()/results.json 是精简过的结构化摘要，不落这两个字段，
    # 避免 JSON 文件因内嵌大量 base64 媒体数据而膨胀。
    media_image_data_uri: str = ""
    media_audio_data_uri: str = ""
    media_asset_label: str = ""


@dataclass
class CrashEvent:
    timestamp: str
    model_name: str
    round_num: int
    endpoint: str
    detail: str
    # 进程崩溃时的 stderr/stdout 日志尾部,便于诊断。远程模式(RemoteServiceManager)
    # 没有本地日志文件时留空,不报错。
    log_tail: str = ""
    # 崩溃发生前最近若干次请求的快照(模型/端点/轮次/请求上下文),用于追溯崩溃发生时
    # 的上下文关联。由 _trace_snapshot() 生成,可能为空字符串(尚无历史记录或调用方未接入)。
    request_history: str = ""


# ============================================================================
# 全局请求追踪环形缓冲区 —— 崩溃可追溯性基础设施
# ============================================================================
# 记录最近若干次 HTTP 请求(跨模型/跨轮次,同一进程生命周期内全局共享,而不是每个 APITester
# 实例各自维护一份),供崩溃发生时回溯"崩溃前到底发生了什么"：测过哪些模型、按什么顺序切换、
# 多模态请求具体用的是哪个素材文件。这是排查"交替执行大语言模型和多模态模型是否导致上下文
# 未清理干净"、"是否某个特定图片诱发崩溃"这类假设时必需的证据链，而不是事后凭猜测归因。
_REQUEST_TRACE_MAXLEN = 12
_request_trace_lock = threading.Lock()
_request_trace = collections.deque(maxlen=_REQUEST_TRACE_MAXLEN)


def _trace_request(model_name, endpoint_name, round_num, context=""):
    """记录一次即将发出的请求(在实际发送前调用,即使随后失败/崩溃也已经被记录下来)。"""
    with _request_trace_lock:
        _request_trace.append({
            "ts": datetime.now().strftime("%H:%M:%S.%f")[:-3],
            "model": model_name, "endpoint": endpoint_name,
            "round": round_num, "context": context,
        })


def _trace_snapshot():
    """返回当前追踪缓冲区的快照文本(按时间顺序,最近的在最后),用于写入 CrashEvent.request_history。"""
    with _request_trace_lock:
        items = list(_request_trace)
    if not items:
        return ""
    return " -> ".join(
        f"[{e['ts']}] {e['model']}/R{e['round']} {e['endpoint']}" + (f" ({e['context']})" if e['context'] else "")
        for e in items
    )


def wait_port_open(host, port, timeout=120, process=None):
    """轮询 TCP 端口直到可连接;不依赖任何 HTTP 路由。

    用于服务启动后等待 `httplib::Server::listen` 真正完成端口绑定,
    避免后续 HTTP 请求出现 ConnectionRefused。

    如果传入 ``process`` (subprocess.Popen),每次轮询前先 poll() 一次:
    一旦发现子进程已退出,立即 raise RuntimeError(带 exit code),
    避免在子进程秒退的情况下还死等满 timeout 秒。
    """
    import socket
    end = time.time() + timeout
    while time.time() < end:
        if process is not None:
            rc = process.poll()
            if rc is not None:
                raise RuntimeError(
                    f"GenieAPIService.exe 启动后立即退出 (exit_code={rc})；"
                    f"端口 {host}:{port} 永远不会监听"
                )
        s = socket.socket(socket.AF_INET, socket.SOCK_STREAM)
        s.settimeout(1.0)
        try:
            s.connect((host, port))
            return True
        except (ConnectionRefusedError, OSError, socket.timeout):
            pass
        finally:
            try:
                s.close()
            except Exception:
                pass
        time.sleep(0.5)
    return False


def wait_port_closed(host, port, timeout=15):
    """轮询直到 TCP 端口不再可连接(即上一个进程已释放监听)。用于两次连续启动之间
    (如 run_graceful_shutdown_tests 连续对 qnn/GGUF/mnn 三个后端各重启一次)避免
    上一个进程的端口释放存在延迟(TIME_WAIT/OS 调度)导致下一次 start() 命中
    "service already exist."(isPortAvailable() 判定端口被占用而立即退出,exit_code=0)。
    超时仍视为"端口未确认释放"返回 False,但不阻塞太久 —— 调用方仍会继续尝试启动,
    真正的失败原因(端口占用)会在 start() 自身的日志里体现,不会被这里的判断掩盖。"""
    import socket
    end = time.time() + timeout
    while time.time() < end:
        s = socket.socket(socket.AF_INET, socket.SOCK_STREAM)
        s.settimeout(1.0)
        try:
            s.connect((host, port))
            s.close()
        except (ConnectionRefusedError, OSError, socket.timeout):
            return True
        time.sleep(0.5)
    return False


def wait_http_ok(url, timeout=60, expected_status=200, process=None):
    end = time.time() + timeout
    last_error = ""
    while time.time() < end:
        if process is not None:
            rc = process.poll()
            if rc is not None:
                raise RuntimeError(f"HTTP 服务启动后立即退出 (exit_code={rc}); last_error={last_error}")
        try:
            r = requests.get(url, timeout=3)
            if r.status_code == expected_status:
                return True
            last_error = f"status={r.status_code}, body={r.text[:500]}"
        except Exception as e:
            last_error = repr(e)
        time.sleep(1)
    raise RuntimeError(f"HTTP 服务在 {timeout}s 内未就绪: {url}; last_error={last_error}")


# ============================================================================
# PerfMonitor - 后台性能采样器
# ============================================================================
class PerfMonitor:
    """后台性能采样器。

    关键点 (CPU 采样修复):
    psutil 的 Process.cpu_percent(interval=None) 返回的是"距上次同一 Process 对象
    调用 cpu_percent 以来"的 CPU 利用率。如果每次都 new 一个新的 psutil.Process(pid),
    "上次调用"为空,返回值永远是 0.0 —— 这也是之前 CPU 总是 N/A 的根因。

    修复:
      - 持有一个长生命周期的 psutil.Process 实例 self._proc;
      - 在 start() 里立即调一次 cpu_percent() 进行 prime (建立基线);
      - 之后 _sample_loop 和 snapshot 都复用同一个 self._proc, 不再 new。
    """
    def __init__(self):
        self._thread = None
        self._stop_event = threading.Event()
        self._samples = []
        self._pid = None
        self._proc = None
        self._lock = threading.Lock()

    def start(self, pid):
        if not HAS_PSUTIL:
            return
        self._pid = pid
        self._stop_event.clear()
        self._samples = []
        try:
            self._proc = psutil.Process(pid)
            self._proc.cpu_percent(interval=None)
        except (psutil.NoSuchProcess, psutil.AccessDenied):
            self._proc = None
            return
        self._thread = threading.Thread(target=self._sample_loop, daemon=True)
        self._thread.start()

    def _sample_loop(self):
        if self._proc is None:
            return
        while not self._stop_event.is_set():
            try:
                mem = self._proc.memory_info().rss / (1024 * 1024)  # MB
                # 可能 > 100%(多核累加),报告展示层会按逻辑核心数归一化后再展示。
                cpu = self._proc.cpu_percent(interval=None)
                sample = {
                    "timestamp": time.time(),
                    "rss_mb": round(mem, 2),
                    "cpu_percent": round(cpu, 1)
                }
                with self._lock:
                    self._samples.append(sample)
            except (psutil.NoSuchProcess, psutil.AccessDenied):
                break
            self._stop_event.wait(1.0)

    def snapshot(self):
        if not HAS_PSUTIL or self._proc is None:
            return {}
        try:
            mem = self._proc.memory_info().rss / (1024 * 1024)
            cpu = self._proc.cpu_percent(interval=None)
            return {
                "timestamp": time.time(),
                "rss_mb": round(mem, 2),
                "cpu_percent": round(cpu, 1)
            }
        except (psutil.NoSuchProcess, psutil.AccessDenied):
            return {}

    def stop(self):
        self._stop_event.set()
        if self._thread and self._thread.is_alive():
            self._thread.join(timeout=3)
        with self._lock:
            return list(self._samples)

    def get_samples(self):
        with self._lock:
            return list(self._samples)


# ============================================================================
# RemoteServiceManager - 远程服务（不管理进程生命周期）
# ============================================================================
class RemoteServiceManager:
    """用于连接已在运行的远程服务，不管理进程生命周期。
    is_alive() 始终返回 True（避免每次请求前都轮询 /models），
    实际连通性通过 check_connectivity() 在测试开始时验证一次。
    """
    def __init__(self, host, port):
        self.host = host
        self.port = port
        # 与 ServiceManager 保持一致的"MNN OOM 已发生"标记；远程模式下 restart() 同样会重置。
        self.mnn_oom_event = None

    def start(self, config_path=None):
        pass

    def check_connectivity(self, timeout=10):
        """实际验证一次服务是否可达（仅在测试开始时调用）"""
        url = f"http://{self.host}:{self.port}/models"
        start = time.time()
        while time.time() - start < timeout:
            try:
                r = requests.get(url, timeout=5)
                if r.status_code == 200:
                    return True
            except (requests.ConnectionError, requests.Timeout):
                pass
            time.sleep(2)
        return False

    def stop(self):
        pass

    def is_alive(self):
        # 远程模式：始终返回 True，避免每次请求前都调用 /models
        # 如果服务真的断开，_safe_request 的异常处理会捕获
        return True

    def restart(self):
        # 远程模式无法重启，但检查一次连通性；既然认定为一次新的连接生命周期,
        # 同样重置 MNN OOM 标记,不带着上一次连接期间的历史包袱。
        self.mnn_oom_event = None
        return self.check_connectivity(timeout=10)

    def get_pid(self):
        return None


# ============================================================================
# QAIModelBuilderManager - Builder 后端生命周期管理
# ============================================================================
# 当前 QAIModelBuilder 仓库已从扁平 backend/main.py 结构重构为 DDD 分层的
# apps/api/main.py（详见 apps/api/__main__.py），旧的 backend/ 目录与 /api/health
# 端点均已不存在；本类已按当前版本重写启动方式、健康检查与 CSRF 双提交会话。

def _default_builder_python_path():
    """QAIModelBuilder 官方 Setup.bat 搭建的独立 ARM64 venv 的默认 python.exe 路径。"""
    return Path(os.environ.get("LOCALAPPDATA", "")) / "QAIModelBuilder" / "envs" / ".venv_arm64_313" / "Scripts" / "python.exe"


def resolve_builder_python(explicit_path=None):
    """解析用于启动 QAIModelBuilder 的 python.exe：优先用户显式传入 --builder_python；
    否则尝试官方 Setup.bat 搭建的默认 venv；都找不到则回退 sys.executable 并打印明确警告
    （而不是静默失败——系统 Python 通常缺 pydantic_settings 等 Builder 必需依赖）。"""
    if explicit_path:
        p = Path(explicit_path)
        if p.exists():
            return str(p)
        print(f"WARNING: --builder_python 指定的路径不存在: {p}，回退到 sys.executable ({sys.executable})")
        return sys.executable
    default_venv = _default_builder_python_path()
    if default_venv.exists():
        return str(default_venv)
    print(f"WARNING: 未找到 QAIModelBuilder 官方 venv ({default_venv})，回退到 sys.executable "
          f"({sys.executable})；若该环境缺少 pydantic_settings 等依赖，Builder 启动会失败。"
          f"请先运行 QAIModelBuilder\\Setup.bat 搭建独立环境，或通过 --builder_python 显式指定。")
    return sys.executable


def cleanup_junctions(paths):
    """移除 `mklink /J` 创建的目录联接本身（不触碰联接指向的真实目录）。

    根因（见 docs/known-issues.md 7.1b 根因③）：这些联接把 `<out_dir>/qaimodelbuilder_data/
    {models,bin}/<name>` 指向真实的 `GenieEnv\\models\\<name>`/GenieAPIService 安装目录；
    `<out_dir>` 若未被 `.gitignore` 覆盖，远程同步的 `git clean -fd` 会顺着联接钻进去删除
    真实目录下未被忽略的文件（典型是 config.json）。`.gitignore` 规则是第一道防线（整个
    输出目录被跳过），这里是第二道（纵深防御）：即使某次输出目录意外未被忽略，联接本身
    也不会残留到下一次同步。调用方必须在 `finally` 里无条件调用，覆盖正常/异常两条路径。

    判存在性不能用 `Path.exists()`：Windows 目录联接一旦目标被删除（悬空联接），
    `Path.exists()`/`os.path.exists()` 会沿联接解析到不存在的目标后返回 False，导致悬空
    联接被静默跳过清理——与本函数的清理承诺直接矛盾（已用本地构造的悬空联接验证过这个
    差异）。`os.path.lexists()` 不解析链接本身，联接节点存在就返回 True，无论目标是否存在，
    因此改用它。即使路径根本不存在，下面的 `rmdir` 也只会返回非零退出码，不会抛异常。
    """
    for p in paths:
        try:
            path = Path(p)
            if os.path.lexists(path):
                subprocess.run(["cmd.exe", "/c", "rmdir", str(path)],
                                capture_output=True, text=True, timeout=15)
        except (OSError, subprocess.SubprocessError):
            pass


class _CsrfSession:
    """包一层 requests.Session，实现 QAIModelBuilder 的 CSRF 双提交 Cookie 握手：
    对安全方法(GET/HEAD/OPTIONS)请求，如响应尚未带 cookie 则中间件会自动 Set-Cookie
    qai_csrf=<token>；对非安全方法(POST/PUT/PATCH/DELETE)，自动在 Cookie 基础上附加
    X-QAI-CSRF 头（取值与 cookie 相同），满足双提交校验，否则会被 403
    security.csrf.missing 拒绝。参考 QAIModelBuilder/scripts/native_e2e/_phase2_common.py
    的握手实现（cookie/header 名字、安全方法集合均与其保持一致）。"""
    CSRF_COOKIE_NAME = "qai_csrf"
    CSRF_HEADER_NAME = "X-QAI-CSRF"
    SAFE_METHODS = frozenset({"GET", "HEAD", "OPTIONS"})

    def __init__(self, base_url):
        self.base_url = base_url
        self.session = requests.Session()

    def ensure_csrf_token(self, timeout=10):
        """对健康检查端点（安全方法、公开路径）发一次 GET，收获 Set-Cookie（若尚未持有）。
        返回当前持有的 token；CSRF 已被关闭时返回 None（调用方应据此优雅降级，不强行附加空头）。"""
        token = self.session.cookies.get(self.CSRF_COOKIE_NAME)
        if token:
            return token
        try:
            self.session.get(f"{self.base_url}/api/system/health", timeout=timeout)
        except Exception:
            pass
        return self.session.cookies.get(self.CSRF_COOKIE_NAME)

    def request(self, method, path, timeout=30, **kwargs):
        method_upper = method.upper()
        headers = dict(kwargs.pop("headers", None) or {})
        if method_upper not in self.SAFE_METHODS:
            token = self.ensure_csrf_token(timeout=min(timeout, 10))
            if token:
                headers[self.CSRF_HEADER_NAME] = token
        return self.session.request(method_upper, f"{self.base_url}{path}", headers=headers, timeout=timeout, **kwargs)

    def get(self, path, timeout=30, **kwargs):
        return self.request("GET", path, timeout=timeout, **kwargs)

    def post(self, path, timeout=30, **kwargs):
        return self.request("POST", path, timeout=timeout, **kwargs)


class QAIModelBuilderManager:
    def __init__(self, builder_dir, host, port, log_dir=None, python_exe=None, data_dir=None):
        self.builder_dir = Path(builder_dir)
        # 当前版本入口是 apps/api/main.py（DDD 分层），不再是 backend/main.py。
        self.main_entry = self.builder_dir / "apps" / "api" / "main.py"
        self.host = host
        self.port = port
        self.python_exe = python_exe or sys.executable
        # 隔离的 QAI_DATA__DATA_DIR：每次测试运行独立，不污染 Builder 仓库自身或用户真实数据。
        self.data_dir = Path(data_dir) if data_dir else None
        self.process = None
        self._log_dir = Path(log_dir) if log_dir else self.builder_dir
        self._stdout_fh = None
        self._stderr_fh = None
        self._stdout_log = None
        self._stderr_log = None
        self.csrf = _CsrfSession(self.base_url)

    @property
    def base_url(self):
        return f"http://{self.host}:{self.port}"

    def start(self, timeout=90):
        if not self.builder_dir.exists():
            raise FileNotFoundError(f"找不到 QAIModelBuilder 目录: {self.builder_dir}")
        if not self.main_entry.exists():
            raise FileNotFoundError(
                f"找不到 QAIModelBuilder 后端入口: {self.main_entry}"
                f"（当前版本 Builder 已重构为 DDD 分层结构，不再是 backend/main.py）"
            )
        self._log_dir.mkdir(parents=True, exist_ok=True)
        self._stdout_log = self._log_dir / "qaimodelbuilder_stdout.log"
        self._stderr_log = self._log_dir / "qaimodelbuilder_stderr.log"
        self._stdout_fh = open(self._stdout_log, "wb")
        self._stderr_fh = open(self._stderr_log, "wb")
        # apps.api 依赖绝对包名导入（interfaces.*、qai.platform.* 等），-m 启动本身不会把
        # builder_dir/src 加入 sys.path；对齐仓库自带 Start.bat 的做法：PYTHONPATH=src;. ,
        # cwd=builder_dir。
        src_dir = self.builder_dir / "src"
        env = os.environ.copy()
        pythonpath_parts = [str(src_dir), str(self.builder_dir)]
        existing_pythonpath = env.get("PYTHONPATH", "")
        if existing_pythonpath:
            pythonpath_parts.append(existing_pythonpath)
        env["PYTHONPATH"] = os.pathsep.join(pythonpath_parts)
        # 关闭 Okta 登录门禁（项目文档认可的测试场景用法），CSRF 双提交防护保持开启，
        # 由 self.csrf 会话负责真实握手。
        env["QAI_AUTH__ENABLED"] = "false"
        # 本类拉起的 Builder 是隔离的一次性实例(供 skill_capacity builder 模式等测试复用),
        # 不需要任何文件防护;关掉进程内 AI 文件工具护栏与 guard64.dll OS 级钩子,避免其对被
        # 拉起的 GenieAPIService.exe 子进程链路产生任何干扰(protected_paths 只注入 Python
        # 子进程、关不掉,但本就不影响原生 exe)。
        env["QAI_SECURITY__FILE_GUARD_ENABLED"] = "false"
        env["QAI_SECURITY__NATIVE_FILE_GUARD_ENABLED"] = "false"
        if self.data_dir:
            self.data_dir.mkdir(parents=True, exist_ok=True)
            env["QAI_DATA__DATA_DIR"] = str(self.data_dir)
        cmd = [self.python_exe, "-m", "apps.api", "--host", self.host, "--port", str(self.port)]
        print(f"  [QAIModelBuilderManager] 启动 Builder: {' '.join(cmd)}")
        print(f"  [QAIModelBuilderManager] cwd={self.builder_dir}; PYTHONPATH={env['PYTHONPATH']}"
              + (f"; QAI_DATA__DATA_DIR={self.data_dir}" if self.data_dir else ""))
        self.process = subprocess.Popen(
            cmd,
            cwd=str(self.builder_dir),
            stdout=self._stdout_fh,
            stderr=self._stderr_fh,
            env=env,
            creationflags=subprocess.CREATE_NEW_PROCESS_GROUP if sys.platform == 'win32' else 0
        )
        atexit.register(self._cleanup)
        try:
            wait_http_ok(f"{self.base_url}/api/system/health", timeout=timeout, process=self.process)
        except RuntimeError as e:
            stderr_tail = ServiceManager.read_log_tail(self._stderr_log, 50)
            stdout_tail = ServiceManager.read_log_tail(self._stdout_log, 20)
            self._force_kill()
            raise RuntimeError(
                f"QAIModelBuilder 启动失败: {e}; "
                f"stderr_log={self._stderr_log}; stderr_tail={stderr_tail!r}; stdout_tail={stdout_tail!r}"
            )
        # 就绪后立即完成一次 CSRF 握手，确保后续所有非安全方法请求都能带上正确的双提交凭证。
        self.csrf.ensure_csrf_token(timeout=10)

    def health(self):
        try:
            r = self.csrf.get("/api/system/health", timeout=5)
            return r.status_code == 200, r.status_code, r.text[:500]
        except Exception as e:
            return False, 0, repr(e)

    # ---- 技能面板 API 封装（供 skill_capacity builder 模式等真实多轮 agent 测试复用）----
    # 均沿用 health() 同一套风格：返回 (success_bool, status_code, response_json_or_text)，
    # 复用 self.csrf 已完成的 CSRF 双提交握手，不重新发明 HTTP 调用方式；请求异常不抛出，
    # 折算为 (False, 0, repr(e))。真实路由已核实存在于 interfaces/http/routes/user_prefs.py。
    def get_skills_policy(self, timeout=15):
        """GET /api/skills/policy：读取当前技能启用状态（哪些技能启用、当前模式 manual/auto）。"""
        try:
            r = self.csrf.get("/api/skills/policy", timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def set_skills_mode(self, mode, timeout=15):
        """POST /api/skills/set_mode：切换技能启用模式，body={"mode": "manual"|"auto"}。"""
        try:
            r = self.csrf.post("/api/skills/set_mode", json={"mode": mode}, timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def toggle_skill(self, skill_name, enabled, timeout=15):
        """POST /api/skills/toggle：显式启用/禁用指定技能（如 "weather"）。
        字段名已核实（本机只读 clone `interfaces/http/routes/user_prefs.py` 的
        `SkillToggleRequest`）：body={"skill_name": <name>, "enabled": <bool>}。"""
        try:
            r = self.csrf.post("/api/skills/toggle",
                               json={"skill_name": skill_name, "enabled": bool(enabled)}, timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def reload_skills(self, timeout=30):
        """POST /api/skills/reload：触发技能重新发现（无 body，空 JSON 对象）。"""
        try:
            r = self.csrf.post("/api/skills/reload", json={}, timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def set_skill_run_mode(self, skill_id, mode, timeout=15):
        """POST /api/skills/{skill_id}/set_mode：真正决定某技能是否进入聊天 prompt 的接口
        (`frontend/src/stores/skills.ts` 的 Skills 面板用的就是这一个)。mode ∈
        {"off","cloud","local","both"}。

        本轮核实发现的重要 drift：上面 `set_skills_mode()`/`toggle_skill()` 命中的
        `/api/skills/set_mode`（无 id）与 `/api/skills/toggle` 实际是 AI-Coding 能力策略子系统
        （Security > Skill 面板，管全局 auto/manual 模式与只读/写路径白名单），与"某技能是否在
        普通聊天里对模型可见"完全无关；`resolve_skill_mode()`
        (`qai/platform/skills/discovery.py:63`) 是 Skills 面板/Security 面板/聊天 prompt 门控
        共享的唯一解析函数，但显式 `mode` 字段优先级高于 legacy `enabled` 布尔——因此要让本地
        模型场景稳定看到某技能，必须调用这个按 skill_id 走路径参数的端点并传 "local"/"both"，
        不能依赖 `toggle_skill()` 写入的 `enabled` 兜底（那条兜底只会解析成 "cloud"）。"""
        try:
            r = self.csrf.post(f"/api/skills/{skill_id}/set_mode", json={"mode": mode}, timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def list_skills(self, timeout=15):
        """GET /api/skills：v1 风格技能清单（含每个技能已解析出的 `mode`），用于复核
        `set_skill_run_mode()` 调用后目标技能的解析结果，而不是只信任 set_mode 响应的 200。"""
        try:
            r = self.csrf.get("/api/skills", timeout=timeout)
            return r.status_code == 200, r.status_code, (r.json() if r.status_code == 200 else r.text[:500])
        except Exception as e:
            return False, 0, repr(e)

    def stop(self):
        try:
            self.csrf.post("/api/service/stop", json={}, timeout=10)
        except Exception:
            pass
        if self.process is None:
            self._close_logs()
            return
        try:
            self.process.terminate()
            self.process.wait(timeout=15)
        except subprocess.TimeoutExpired:
            self._force_kill()
            return
        except Exception:
            pass
        self.process = None
        self._close_logs()

    def is_alive(self):
        if self.process is None:
            return False
        return self.process.poll() is None

    def get_exit_code(self):
        """返回子进程的真实退出码;进程仍存活或已被清理(self.process is None)时返回 None。
        与 ServiceManager.get_exit_code 同样的语义,供 QAIModelBuilder 后端进程崩溃诊断复用。"""
        if self.process is None:
            return None
        return self.process.poll()

    def _close_logs(self):
        for fh_attr in ("_stdout_fh", "_stderr_fh"):
            fh = getattr(self, fh_attr, None)
            if fh:
                try:
                    fh.close()
                except Exception:
                    pass
                setattr(self, fh_attr, None)

    def _force_kill(self):
        if self.process:
            try:
                self.process.kill()
                self.process.wait(timeout=5)
            except Exception:
                pass
            self.process = None
        self._close_logs()

    def _cleanup(self):
        self._force_kill()

    def get_pid(self):
        if self.process:
            return self.process.pid
        return None


# ============================================================================
# ServiceManager - 服务生命周期管理
# ============================================================================
class ServiceManager:
    def __init__(self, exe_dir, host, port):
        self.exe_dir = Path(exe_dir)
        self.exe_path = self.exe_dir / "GenieAPIService.exe"
        self.host = host
        self.port = port
        self.process = None
        self._current_config = None
        self._log_dir = None
        self._stdout_fh = None
        self._stderr_fh = None
        self._stdout_log = None
        self._stderr_log = None
        # 当前进程生命周期内是否已发生过 MNN 自身 OOM 事件(见 _mark_mnn_oom/_classify_process_down);
        # 新进程是全新生命周期,不应带着上一个进程的历史包袱,restart() 中会重置为 None。
        self.mnn_oom_event = None

    def start(self, config_path, extra_args=None, extra_env=None):
        if not self.exe_path.exists():
            raise FileNotFoundError(f"找不到 {self.exe_path}")
        # 关键修复:GenieAPIService.exe 用 Popen(cwd=self.exe_dir) 启动,
        # 如果 config_path 是相对路径 (例如 "models\\xxx\\config.json"),
        # 服务侧会按 cwd=Stable\ 去找,得到 Stable\models\xxx\config.json,自然找不到。
        # 这里强制把配置路径解析为绝对路径,根除相对路径歧义。
        # 同时校验文件存在,失败时直接抛 FileNotFoundError,
        # 比让服务端打 "[E] config file is not found" 然后秒退要友好得多。
        cfg_abs = Path(config_path).resolve()
        if not cfg_abs.exists():
            raise FileNotFoundError(f"找不到 config 文件: {cfg_abs}")
        self._current_config = str(cfg_abs)
        cmd = [
            str(self.exe_path.resolve()),
            "-c", str(cfg_abs),
            "-l",
            "-p", str(self.port)
        ]
        # extra_args: 可选的额外命令行参数（如 ["-n", "-1", "-d", "4"]），追加在既有参数之后；默认 None/空列表时不追加任何参数。
        if extra_args:
            cmd.extend(str(a) for a in extra_args)
        env = {**os.environ, **(extra_env or {})}
        print(f"  [ServiceManager] 启动服务: {' '.join(cmd)}")
        # 重要：不要用 subprocess.PIPE 接 GenieAPIService 的 stdout/stderr，
        # QNN 初始化会输出大量日志，PIPE 缓冲区填满后子进程会阻塞，导致服务无法响应。
        # 这里直接落到日志文件（覆盖模式，每次启动会清空旧日志，避免越写越大）。
        log_dir = Path(self._log_dir) if self._log_dir else self.exe_dir
        log_dir.mkdir(parents=True, exist_ok=True)
        self._stdout_log = log_dir / "genie_service_stdout.log"
        self._stderr_log = log_dir / "genie_service_stderr.log"
        self._stdout_fh = open(self._stdout_log, "wb")
        self._stderr_fh = open(self._stderr_log, "wb")
        self.process = subprocess.Popen(
            cmd,
            cwd=str(self.exe_dir),
            stdout=self._stdout_fh,
            stderr=self._stderr_fh,
            env=env,
            creationflags=subprocess.CREATE_NEW_PROCESS_GROUP if sys.platform == 'win32' else 0
        )
        atexit.register(self._cleanup)
        # 启动后立即做一次"秒退检测":
        # ARM64/x86-64 架构不匹配、缺 DLL、OneDrive 占位符未下载等失败,
        # GenieAPIService.exe 会在毫秒级内退出。如果不在这里探测,
        # 后面 wait_port_open 会傻等满 120 秒才报错,
        # 而且报告里看不到"启动失败"这一类事件。
        # 这里给 2 秒窗口,足够覆盖正常情况下尚未完成 listen 的"还活着但没绑端口",
        # 同时把秒退快速暴露出来。
        time.sleep(2)
        rc = self.process.poll()
        if rc is not None:
            stderr_tail = self.read_log_tail(self._stderr_log, 50)
            stdout_tail = self.read_log_tail(self._stdout_log, 20)
            # 释放当前 Popen + 日志句柄,让后续 _cleanup 不再尝试 kill 已退出的进程
            try:
                self._stdout_fh.close()
            except Exception:
                pass
            try:
                self._stderr_fh.close()
            except Exception:
                pass
            self._stdout_fh = None
            self._stderr_fh = None
            self.process = None
            raise RuntimeError(
                f"GenieAPIService.exe 启动后立即退出 (exit_code={rc}); "
                f"stderr_log={self._stderr_log}; "
                f"stderr_tail={stderr_tail!r}; "
                f"stdout_tail={stdout_tail!r}"
            )

    @staticmethod
    def read_log_tail(log_path, n=50):
        """读取日志文件最后 n 行(用 latin-1 兜底,容忍非 UTF-8 内容)。"""
        if log_path is None:
            return ""
        try:
            p = Path(log_path)
            if not p.exists() or p.stat().st_size == 0:
                return ""
            with open(p, "rb") as f:
                data = f.read()
            text = data.decode("utf-8", errors="replace")
            lines = text.splitlines()
            return "\n".join(lines[-n:]).strip()
        except Exception as e:
            return f"<read_log_tail error: {e}>"

    def stop(self):
        if self.process is None:
            return
        try:
            url = f"http://{self.host}:{self.port}/servicestop"
            requests.post(url, json={"text": "stop"}, timeout=10)
        except Exception:
            pass
        try:
            self.process.wait(timeout=15)
        except subprocess.TimeoutExpired:
            self._force_kill()
        self.process = None

    def is_alive(self):
        if self.process is None:
            return False
        return self.process.poll() is None

    def get_exit_code(self):
        """返回子进程的真实退出码;进程仍存活或已被清理(self.process is None)时返回 None。
        调用时机很关键：必须在 restart()/_force_kill() 把 self.process 置空之前调用，
        否则永远拿到 None——这是判定"这次崩溃到底是谁的问题"最直接的证据(见 _describe_exit_code),
        不能靠事后猜测。"""
        if self.process is None:
            return None
        return self.process.poll()

    def restart(self):
        self._force_kill()
        # 旧进程已被强制杀掉,新进程即将启动的是全新生命周期,重置 MNN OOM 标记,
        # 不能让新进程带着上一个进程的历史包袱。
        self.mnn_oom_event = None
        time.sleep(2)
        if self._current_config:
            try:
                self.start(self._current_config)
            except (RuntimeError, FileNotFoundError) as e:
                # 启动秒退,重启失败 — 把异常吞掉,返回 False 让上层 _safe_request 走"崩溃后重启失败"分支。
                print(f"  [ServiceManager] 重启失败: {e}")
                return False
            # 重启后等待端口重新绑定 (TCP 轮询,不依赖任何 HTTP 路由);
            # 同时把 self.process 传进去,这样子进程秒退能立刻被发现而不是空等 120 秒。
            try:
                wait_port_open(self.host, self.port, timeout=120, process=self.process)
            except RuntimeError as e:
                print(f"  [ServiceManager] 重启后等端口失败: {e}")
                return False
            return True
        return False

    def _force_kill(self):
        if self.process:
            try:
                self.process.kill()
                self.process.wait(timeout=5)
            except Exception:
                pass
            self.process = None
        # 关闭日志文件句柄，防止下一次 start 占用同名文件失败
        for fh_attr in ("_stdout_fh", "_stderr_fh"):
            fh = getattr(self, fh_attr, None)
            if fh:
                try:
                    fh.close()
                except Exception:
                    pass
                setattr(self, fh_attr, None)

    def _cleanup(self):
        self._force_kill()

    def get_pid(self):
        if self.process:
            return self.process.pid
        return None


_MODEL_DEFECT_MARKER = "[MODEL_DEFECT] reason="


def _parse_model_defect_line(line):
    """解析一行服务端日志,提取 [MODEL_DEFECT] 标记携带的 reason/model/token_size。
    两种已知形式(genie.cpp 的 sdk_context_exceeded 带 model= 字段,genie_interface.cpp 的
    self_estimated_limit_exceeded 不带)字段顺序不完全固定,因此分别独立 search 而不是要求
    整行匹配一个固定顺序的正则。命中 reason= 与 token_size= 才视为有效(model= 可选)。"""
    if _MODEL_DEFECT_MARKER not in line:
        return None
    reason_m = re.search(r"reason=(\S+)", line)
    token_m = re.search(r"token_size=(\d+)", line)
    if not reason_m or not token_m:
        return None
    model_m = re.search(r"model=(\S+)", line)
    return {
        "reason": reason_m.group(1),
        "model": model_m.group(1) if model_m else None,
        "token_size": int(token_m.group(1)),
    }


def _scan_model_defect_text(text):
    """在一段文本(可能多行)里查找第一条 [MODEL_DEFECT] 标记并解析,未命中返回 None。
    供 _scan_model_defect_log()(按字节偏移读取服务日志)与 SampleApp 场景(直接扫描
    子进程自身捕获到的完整 stdout)共用同一份解析逻辑。"""
    if not text:
        return None
    for line in text.splitlines():
        if _MODEL_DEFECT_MARKER in line:
            parsed = _parse_model_defect_line(line)
            if parsed:
                return parsed
    return None


def _scan_model_defect_log(log_path, offset_before):
    """只扫描服务 stdout 日志文件里 offset_before 之后新增的字节,查找本次请求是否触发了
    [MODEL_DEFECT] 标记(见 genie.cpp/genie_interface.cpp 的 ERROR 级日志)。这样可以精确
    限定到"这一次请求的窗口",不会误判为同一进程生命周期内更早请求残留的标记,也不用担心
    与仍在写入日志的服务进程发生读取竞争(按字节偏移只读已落盘的旧内容)。
    log_path 为 None(如远程模式,或 RemoteServiceManager 没有本地日志文件)时直接返回 None。
    若日志文件在两次调用之间被重启截断(ServiceManager.start() 以"wb"模式重新打开同名文件),
    当前文件大小可能小于 offset_before,此时退化为从文件开头扫描,不抛异常。"""
    if log_path is None:
        return None
    try:
        p = Path(log_path)
        if not p.exists():
            return None
        size = p.stat().st_size
        start = offset_before if (offset_before is not None and offset_before <= size) else 0
        with open(p, "rb") as f:
            f.seek(start)
            data = f.read()
        text = data.decode("utf-8", errors="replace")
    except Exception:
        return None
    return _scan_model_defect_text(text)


def _capability_issue_from_model_defect(defect):
    """把 _scan_model_defect_log()/_scan_model_defect_text() 返回的 dict 转换为
    (model_capability_issue, model_capability_reason) 这对通用诊断字段的取值,
    供各 chat 测试方法构造 TestResult 时直接复用。defect 为 None 时返回 (False, "")。"""
    if not defect:
        return False, ""
    model_part = f", model={defect['model']}" if defect.get("model") else ""
    reason = f"模型缺陷(服务端日志): reason={defect['reason']}, token_size={defect['token_size']}{model_part}"
    return True, reason


# 常见的 Windows 进程异常退出码(NTSTATUS,以有符号 32 位整数表示)含义对照表。
# 崩溃发生时把这个"实锤"证据直接附带到诊断信息里,让报告能立即回答"进程到底是怎么退出的",
# 不需要事后翻日志、更不需要猜测——这是本次修复要解决的核心可追溯性缺口。
_WINDOWS_EXIT_CODE_HINTS = {
    -1073741819: "STATUS_ACCESS_VIOLATION(0xC0000005): 空指针/越界内存访问,程序自身代码缺陷",
    -1073740791: "STATUS_STACK_BUFFER_OVERRUN(0xC0000409): 栈缓冲区溢出保护(/GS)触发的 FailFast",
    -1073741571: "STATUS_STACK_OVERFLOW(0xC00000FD): 栈溢出,常见于无限/过深递归",
    -1073740940: "STATUS_HEAP_CORRUPTION(0xC0000374): 堆损坏",
    -1073741515: "STATUS_DLL_NOT_FOUND(0xC0000135): 依赖的 DLL 缺失",
    -1073741701: "STATUS_DLL_INIT_FAILED(0xC0000142): DLL 初始化失败",
    3: "abort()/CRT 断言失败触发的终止",
}

# 与 GenieAPIService.cpp 中 GenieService::ServiceStop() 的关闭看门狗保持一致：底层推理调用
# (如 MNN 在内存压力下的 generate())未在阈值内响应 Stop() 信号时,看门狗会以该退出码强制
# 终止进程。这是已知的兜底路径,不是真实崩溃,必须与 _WINDOWS_EXIT_CODE_HINTS 中的 NTSTATUS
# 崩溃特征码区分开,避免被 graceful_shutdown 测试误判为"崩溃"。
_SHUTDOWN_WATCHDOG_EXIT_CODE = 124
_SHUTDOWN_WATCHDOG_LOG_MARKER = "[shutdown watchdog]"


def _describe_exit_code(exit_code):
    """把进程退出码翻译成人类可读的诊断信息,而不是留一个裸数字或空白让人去猜。
    exit_code 为 None 表示调用时进程已被清理/仍存活,拿不到真实退出码——必须明确说明这一点,
    而不是悄悄留空误导成"没有崩溃"。"""
    if exit_code is None:
        return "未知(进程已被清理或仍存活,无法回溯真实退出码)"
    hint = _WINDOWS_EXIT_CODE_HINTS.get(exit_code)
    try:
        hex_str = f"0x{exit_code & 0xFFFFFFFF:08X}"
    except TypeError:
        hex_str = "?"
    return f"{exit_code} ({hex_str}): {hint}" if hint else f"{exit_code} ({hex_str})"


def _pick_random_asset_file(data_dir, subdir, extensions):
    """从 data_dir/subdir 素材池中随机抽取一个文件(每次调用重新抽取,不缓存)。
    返回 (Path, None) 或 (None, 原因字符串)。供 APITester._pick_random_asset 与
    run_sampleapp_only_tests 共用,避免同一段素材筛选逻辑被复制两份。"""
    if not data_dir:
        return None, "未指定 --data_dir"
    pool_dir = Path(data_dir) / subdir
    if not pool_dir.is_dir():
        return None, f"{pool_dir} 不存在"
    candidates = [f for f in pool_dir.iterdir()
                  if f.is_file() and f.suffix.lower() in extensions]
    if not candidates:
        return None, f"{pool_dir} 下没有找到 {extensions} 素材"
    return random.choice(candidates), None


# SampleApp.cpp 自身定义的、受控的"正常失败"退出码：0=成功,1=模型加载失败,2=推理异常被
# catch 后主动返回,3=打不开输入文件。凡是不在这个集合里的退出码(尤其是大的负数,对应
# Windows NTSTATUS,如 0xC0000005 access violation)都代表进程被操作系统强制终止——
# 这才是真正的崩溃,必须标记 crashed=True,不能和"程序自己判断失败后正常退出"混为一谈。
_SAMPLEAPP_KNOWN_EXIT_CODES = {0, 1, 2, 3}


def _is_sampleapp_crash_exit_code(returncode):
    return returncode not in _SAMPLEAPP_KNOWN_EXIT_CODES


def _capture_log_tail(svc):
    """尝试读取服务进程 stderr/stdout 日志尾部,并把进程真实退出码一并附带,用于崩溃事件诊断。
    退出码是判定"这次崩溃到底是谁的问题"最直接的证据(例如 0xC0000005 access violation
    直接指向程序自身代码缺陷,而不是驱动/环境问题);只有显式实现了 get_exit_code() 的管理类
    (ServiceManager/QAIModelBuilderManager)才会附带这行,RemoteServiceManager 等没有本地
    进程/日志文件的场景下 getattr 拿不到对应属性,行为与之前完全一致(返回空字符串)。"""
    get_exit_code = getattr(svc, "get_exit_code", None)
    exit_code_line = f"exit_code: {_describe_exit_code(get_exit_code())}\n" if callable(get_exit_code) else ""
    read_tail = getattr(svc, "read_log_tail", None)
    if not callable(read_tail):
        return exit_code_line.rstrip("\n")
    stderr_log = getattr(svc, "_stderr_log", None)
    stdout_log = getattr(svc, "_stdout_log", None)
    return f"{exit_code_line}stderr: {read_tail(stderr_log, 30)}\nstdout: {read_tail(stdout_log, 10)}"


# MNN 内存预检查(MnnVerifier)拒绝加载时,无论是 HTTP 响应体的 failure_detail 字段还是
# SampleApp/GenieAPILibrary 进程自身的 stdout 日志,服务端 C++ 侧都统一使用这段文本描述
# 原因,是判定"环境资源约束导致的优雅失败"的精确信号来源,唯一维护点。
_MNN_INSUFFICIENT_MEMORY_MARKER = "insufficient memory to load MNN model"


def _extract_failure_reason(response):
    """从 chat 请求的 HTTP 响应体中提取服务端新增的 failure_reason/failure_detail 字段。
    目前仅 MNN 内存预检查判定内存不足拒绝加载模型时,服务端才会附带这两个字段
    (`{"error": ..., "failure_reason": "insufficient_memory", "failure_detail": "..."}`)；
    这是程序化可识别的权威信号,优先用它判定"服务端优雅拒绝式 OOM",
    而不是继续靠字符串猜测模型名。非 JSON 响应体或不含该字段时返回 (None, None)。"""
    try:
        data = response.json()
    except Exception:
        return None, None
    if isinstance(data, dict):
        reason = data.get("failure_reason")
        if reason:
            return reason, data.get("failure_detail", "")
    return None, None


def _mark_mnn_oom(svc, model_name, detail):
    """在服务进程对象(ServiceManager/RemoteServiceManager 实例)上记录一次 MNN 自身 OOM 事件,
    供同一进程生命周期内其它后端(GGUF/QNN)请求失败时判定"是否为级联受累"提供依据。
    该状态天然与"当前服务进程生命周期"绑定,进程重启时由 restart() 清空。"""
    svc.mnn_oom_event = {
        "timestamp": datetime.now().isoformat(),
        "model_name": model_name,
        "detail": detail,
    }


def _get_mnn_oom_event(svc):
    """读取 svc 上记录的"MNN OOM 已发生"标记,未发生过则返回 None。"""
    return getattr(svc, "mnn_oom_event", None)


def _is_cascading_mnn_oom(svc, model_name):
    """判定这次失败是否是"同一个 MNN 模型此前已被内存预检查(MnnVerifier)优雅拒绝、从未
    加载成功"的级联表现。/profile、/contextsize、/textsplitter 等辅助接口本身的响应体不会
    重新携带 failure_reason(只有直接触发模型加载的请求才会),但它们的失败只是同一次 OOM 的
    后续症状,不应被拆散计成多条独立的 failed(违反"避免错误连坐"的判定原则,见 4.7)。仅当
    该模型是 mnn 后端、且此前(同一进程生命周期内)已经记录过针对这个具体模型名的
    insufficient_memory 事件时才成立。"""
    if infer_backend(model_name)[0] != "mnn":
        return False
    oom_event = _get_mnn_oom_event(svc)
    return bool(oom_event) and oom_event.get("model_name") == model_name


# 进程真正崩溃到 process.poll()/连接被 OS 完全回收之间存在短暂延迟(Windows 上尤其明显,
# 例如崩溃转储采集、句柄清理都需要一点时间)。如果在捕获到 ConnectionError/Timeout 后只做
# 一次立即的 is_alive() 探测就得出结论,真正触发崩溃的那次请求可能因为探测过早而被误判为
# "进程仍存活,普通请求异常"(不计入 crashed),而只有稍晚发出的下一条请求才会命中"进程已死"
# 的判定——结果报告里显示"崩溃于 GET /profile"这类无辜的后续探测,而不是实际造成崩溃的那次
# chat 请求,造成崩溃归因错位、让人误以为是别的接口的问题。这里给一个短暂宽限期,在期限内反复
# 重新探测,让真正致死的那次请求本身就能被正确标记为 crashed=True。
_CRASH_CONFIRM_GRACE_SECONDS = 2.0
_CRASH_CONFIRM_POLL_INTERVAL = 0.2


def _confirm_process_dead(svc, grace_seconds=_CRASH_CONFIRM_GRACE_SECONDS,
                           poll_interval=_CRASH_CONFIRM_POLL_INTERVAL):
    """在捕获到请求异常(ConnectionError/Timeout)后判定服务进程是否真的已经退出。
    立即探测一次为 True 直接返回;否则在宽限期内轮询重试,避免探测早于进程真正终止而
    把这次崩溃错误归因到后续某个无关请求上。宽限期内始终未探测到进程退出则返回 False
    (确实只是这次请求自身的连接异常,进程仍然存活)。"""
    if not svc.is_alive():
        return True
    deadline = time.time() + grace_seconds
    while time.time() < deadline:
        time.sleep(poll_interval)
        if not svc.is_alive():
            return True
    return False


def _classify_process_down(svc, model_name):
    """服务进程当前不存活(或已确认自身导致优雅拒绝)时,判定这次失败该如何归类:

    崩溃永远是异常信号，不存在因同进程内 MNN OOM 拖垮进程而级联失败的自动豁免分支。
    正常的、非崩溃的优雅失败（MNN 内存预检查通过 failure_reason=insufficient_memory
    精确识别）不会造成其它模型的连带失败；只有进程真的崩溃才会连带，而崩溃本身必须
    始终被视为需要排查的真实问题，不能被当作可依赖的设计事实去豁免。

    - 当前模型是 MNN: MNN 自身导致的真实OOM事件/崩溃,ignorable=False,
      并在 svc 上记录"MNN OOM 已发生"标记(仅用于下面的诊断标注)。
    - 当前模型非 MNN: 该模型自身的真实问题,ignorable=False。若检测到此前同进程内发生过
      MNN OOM 事件，仅在 detail 中追加"疑似与此前 MNN OOM 相关，需要人工排查根因"这类
      诊断性提示（ignore_reason 标注为 "mnn_oom_cascade" 供报告侧诊断徽章识别），但不
      设置 ignorable=True——一旦真的观测到这种级联崩溃，说明存在需要排查的真实
      崩溃 bug，必须如实计入 failed/crashed 统计。

    返回 (ignorable, ignore_reason, detail)。
    """
    is_mnn = infer_backend(model_name)[0] == "mnn"
    if is_mnn:
        detail = f"MNN 模型自身导致服务进程崩溃/OOM,这是需要关注的真实OOM事件（模型={model_name}）"
        _mark_mnn_oom(svc, model_name, detail)
        return False, "", detail
    oom_event = _get_mnn_oom_event(svc)
    if oom_event:
        detail = (f"疑似与此前 MNN 模型({oom_event['model_name']}) 于 {oom_event['timestamp']} 发生的 OOM 相关"
                   f"而级联崩溃,但崩溃永远是真实问题,不代表豁免,需要人工排查根因 "
                   f"(model={model_name}, ignore_reason=mnn_oom_cascade 仅作诊断标注)")
        return False, "mnn_oom_cascade", detail
    detail = f"服务进程崩溃,且未检测到此前的 MNN OOM 事件,应视为 {model_name} 自身的真实问题"
    return False, "", detail


# ============================================================================
# tool_calls / function calling 协议测试用到的预定义工具 Schema 与配置读取工具函数
# ============================================================================
# 用于 test_tool_call_model_invocation_probe/test_tool_call_streaming_argument_integrity_probe/
# test_tool_call_round_trip_with_result：prompt_optimizer.cpp:705-727 GetOptimizedToolDefinition
# 预定义工具名表中已确认存在的 "read"，对应的 OpenAI tools[] JSON Schema。与
# run_numresponse_stateless_mode_regressions() 用的 _STATELESS_MODE_READ_TOOL_DEF（module 后面
# 定义）是同一个预定义工具，这里复用同一个常量，不重复定义第二份。


LONG_TOOL_HISTORY_COUNT = 81


# ============================================================================
# APITester - 接口测试执行器（含容错）
# ============================================================================
class APITester:
    def __init__(self, host, port, service_manager, perf_monitor, model_name, total_rounds=1, data_dir=None,
                 all_models=None, multimodal_rounds=None, exe_dir=None):
        self.base_url = f"http://{host}:{port}"
        self.svc = service_manager
        self.perf = perf_monitor
        self.model_name = model_name
        self.crash_events = []
        self._restart_count = 0
        self.MAX_RESTARTS = 3
        self.total_rounds = total_rounds
        self.data_dir = Path(data_dir) if data_dir else None
        # 切换伙伴发现（test_dynamic_switch_multimodal_stability 用）与多模态专属轮数
        # （未显式传入时跟随 total_rounds，保持默认行为不变）。
        self._all_models = all_models or []
        self.multimodal_rounds = multimodal_rounds if multimodal_rounds is not None else total_rounds
        self.exe_dir = exe_dir

    def _capture_log_offset(self):
        """在发出 chat 请求前调用,记录服务 stdout 日志文件当前的(路径, 字节大小)。
        返回值直接传给 _scan_model_defect_log(),用于把"扫描 [MODEL_DEFECT] 标记"精确限定到
        本次请求的窗口。远程模式(RemoteServiceManager 没有 _stdout_log 属性)或日志文件
        尚未创建时返回 None,调用方应据此跳过扫描(不报错)。"""
        log_path = getattr(self.svc, "_stdout_log", None)
        if log_path is None:
            return None
        try:
            return log_path, Path(log_path).stat().st_size
        except Exception:
            return log_path, 0

    def _safe_request(self, method, path, endpoint_name, round_num, request_context="", **kwargs):
        """带崩溃检测的请求包装。request_context 用于记录本次请求的关键上下文(例如多模态请求
        用的图片/音频文件名),它不影响请求本身,只在崩溃发生时随 CrashEvent 一并暴露出来——
        否则崩溃事件只知道"哪个 endpoint 崩了",却看不出当时到底在传哪个素材,复现/归因时
        只能凭猜测。"""
        _trace_request(self.model_name, endpoint_name, round_num, request_context)
        if not self.svc.is_alive():
            if self._restart_count >= self.MAX_RESTARTS:
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=endpoint_name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"服务已崩溃且超过最大重启次数; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason
                )
            # 尝试重启
            self.crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name=self.model_name, round_num=round_num,
                endpoint=endpoint_name, detail="请求前检测到进程已退出",
                log_tail=_capture_log_tail(self.svc), request_history=_trace_snapshot()
            ))
            self._restart_count += 1
            if not self.svc.restart():
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=endpoint_name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"服务重启失败; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason
                )
            # 重启成功后更新 PerfMonitor
            if HAS_PSUTIL and self.svc.get_pid():
                self.perf.stop()
                self.perf.start(self.svc.get_pid())

        url = f"{self.base_url}{path}"
        start_time = time.time()
        try:
            if method == "GET":
                r = requests.get(url, timeout=60, **kwargs)
            else:
                r = requests.post(url, timeout=300, **kwargs)
            latency = (time.time() - start_time) * 1000
            # 服务端优雅拒绝式 OOM(分类A(a)): MNN 内存预检查拒绝加载时,响应体带
            # failure_reason=insufficient_memory,这里只做标记侧记(不改变返回值),
            # 具体 TestResult 的 ignorable/detail 由各调用方(如 test_chat_non_stream)决定。
            if r.status_code == 500 and infer_backend(self.model_name)[0] == "mnn":
                failure_reason, failure_detail = _extract_failure_reason(r)
                if failure_reason == "insufficient_memory":
                    _mark_mnn_oom(self.svc, self.model_name,
                                  f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}")
            return r, latency
        except (requests.ConnectionError, requests.Timeout) as e:
            latency = (time.time() - start_time) * 1000
            # 检查进程是否崩溃(带短暂宽限期重试,避免把真正致死的这次请求误判为"进程仍存活的
            # 普通异常",而让后续某个无关请求背了这次崩溃的锅——见 _confirm_process_dead 注释)
            if _confirm_process_dead(self.svc):
                log_tail = _capture_log_tail(self.svc)
                history = _trace_snapshot()
                is_mnn = infer_backend(self.model_name)[0] == "mnn"
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                context_note = f" [request_context={request_context}]" if request_context else ""
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(),
                    model_name=self.model_name, round_num=round_num,
                    endpoint=endpoint_name,
                    detail=f"请求中服务崩溃: {type(e).__name__}; {classify_detail}{context_note}",
                    log_tail=log_tail, request_history=history
                ))
                self._restart_count += 1
                restarted = False
                if self._restart_count <= self.MAX_RESTARTS:
                    restarted = self.svc.restart()
                    if HAS_PSUTIL and self.svc.get_pid():
                        self.perf.stop()
                        self.perf.start(self.svc.get_pid())
                if is_mnn and restarted:
                    self.crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=self.model_name, round_num=round_num,
                        endpoint="MNN_OOM_CRASH",
                        detail=f"MNN OOM 崩溃后已自动重启(第{self._restart_count}次),跳过该模型本轮剩余测试",
                        log_tail=log_tail, request_history=history
                    ))
                elif ignore_reason == "mnn_oom_cascade":
                    self.crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=self.model_name, round_num=round_num,
                        endpoint="MNN_OOM_CASCADE",
                        detail=classify_detail,
                        log_tail=log_tail, request_history=history
                    ))
                return TestResult(
                    name=endpoint_name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=latency,
                    detail=f"服务崩溃: {type(e).__name__}: {e}; {classify_detail}{context_note}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    auto_restarted=is_mnn and restarted
                )
            return TestResult(
                name=endpoint_name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=latency,
                detail=f"请求异常: {type(e).__name__}: {e}"
            )

    def is_over_restart_limit(self):
        return self._restart_count >= self.MAX_RESTARTS and not self.svc.is_alive()

    def run_global_tests(self):
        """执行模型无关的通用接口测试（只需运行一次）

        覆盖 GenieAPIService.cpp 中"加载模型前可调用"的全部 GET 路由
        及其别名 (/models 与 /v1/models)。
        """
        results = []
        tests = [
            ("GET /", lambda: self.test_welcome(1)),
            ("GET /models", lambda: self.test_models(1, path="/models")),
            ("GET /v1/models", lambda: self.test_models(1, path="/v1/models")),
        ]
        for test_name, test_fn in tests:
            print(f"    测试 {test_name} ... ", end="", flush=True)
            result = test_fn()
            status = "✓ PASS" if result.passed else ("✗ CRASH" if result.crashed else "✗ FAIL")
            print(f"{status} ({result.latency_ms:.0f}ms)")
            results.append(result)
        return results

    def run_all(self, round_num, include_final_cleanup=True):
        """执行一轮模型相关测试,覆盖 GenieAPIService.cpp 注册的所有路由及别名。

        每轮顺序:
          status(before)
          chat 4 个别名 × (non-stream + stream) = 8 次
          status(after)
          profile / contextsize / fetch
          textsplitter × 2 别名
          images × 2 别名
          reload
        图片/音频多模态用例已从这里完全抽离,改由独立的 run_multimodal_rounds() 按
        self.multimodal_rounds 单独驱动,与本方法的 --rounds 循环互不影响、互不放大。
        include_final_cleanup=True 且到达最后一轮时,额外调用 run_final_cleanup()
        追加 stop → clear → unload；调用方需确保多模态轮次已在此之前跑完,
        否则收尾卸载模型后 run_multimodal_rounds() 的请求会触发意外的隐式重新加载。
        (/servicestop 不在这里调用,放在 main() 整轮结束后一次性调用)

        说明:不再使用 `/status` 来判定服务/模型就绪 —— 服务端 `/status`
        在冷启动期间会因为 set_content(json_object) 类型 bug 直接返回 400,
        无法稳定作为 ready 信号。这里把 `/status` 改为观察用:在 chat 前后各
        采一次,报告里能直接看到"前 vs 后"的差异。严格策略下 400 直接判 FAIL。
        """
        self._restart_count = 0
        prompt = TEST_PROMPTS[(round_num - 1) % len(TEST_PROMPTS)]

        # ── 预检：模型是否成功加载（仅用于日志/诊断） ──────────────────────────────
        # 发一个轻量 chat 请求观察模型是否可用。这个探测请求本身**不再**被用来批量豁免
        # 本轮后续任何测试的失败结果——旧版本一旦命中"not found"/"unavailable"等宽泛
        # 子串就把 chat/profile/contextsize/textsplitter/fetch 全部相关失败标记为
        # ignorable=True，这是本次修复要废弃的"一次探测代表一整轮"过度容忍机制。
        # 现在每个具体测试方法（test_chat_non_stream/test_chat_stream 等）已经各自基于
        # failure_reason=="insufficient_memory" 等精确信号独立判定是否为真实错误，
        # 这里的探测只在命中该信号时记录 MNN OOM 事件供诊断/级联判定使用。
        try:
            probe_resp = requests.post(
                f"{self.base_url}/v1/chat/completions",
                json={"model": self.model_name,
                      "messages": [{"role": "user", "content": "hi"}],
                      "stream": False, "max_tokens": 4},
                timeout=60
            )
            if probe_resp.status_code == 500:
                failure_reason, failure_detail = _extract_failure_reason(probe_resp)
                if failure_reason == "insufficient_memory" and infer_backend(self.model_name)[0] == "mnn":
                    _mark_mnn_oom(
                        self.svc, self.model_name,
                        f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
                    )
        except Exception:
            pass  # 连接失败时不做预检，让后续测试正常运行

        # GenieAPIService.cpp 里 ChatCompletions handler 注册的 4 个路径
        chat_paths = ["/v1/chat/completions", "/chat/completions",
                      "/v1/completions", "/completions"]

        tests = []
        # /status (before): 第一次 chat 之前的一次观察
        tests.append((f"GET /status (before chat)",
                      lambda rn=round_num: self.test_status(rn, name="GET /status (before chat)")))

        # 4 个 chat 别名 × (non-stream + stream),共 8 次；每个别名按下标 + 轮次轮流使用
        # CHAT_CONTENT_FORMATS 里的一种 content 格式，确保哪怕默认只跑 1 轮
        # (--rounds 默认为 1)，OpenAI 字符串/数组风格与 GenieAPIClient 对象风格 3 种格式
        # 也都会在单轮内被覆盖到（4 个别名对 3 种格式取模自然循环一遍多），
        # 而不是只测最常见的纯字符串写法；多轮时额外叠加轮次偏移，避免同一别名每轮都固定同一格式。
        for idx, cp in enumerate(chat_paths):
            fmt = CHAT_CONTENT_FORMATS[(idx + round_num - 1) % len(CHAT_CONTENT_FORMATS)]
            tests.append((f"POST {cp} (non-stream)",
                          lambda rn=round_num, p=cp, f=fmt: self.test_chat_non_stream(rn, prompt, path=p, content_format=f)))
            tests.append((f"POST {cp} (stream)",
                          lambda rn=round_num, p=cp, f=fmt: self.test_chat_stream(rn, prompt, path=p, content_format=f)))

        # /status (after): 所有 chat 跑完后再观察一次
        tests.append((f"GET /status (after chat)",
                      lambda rn=round_num: self.test_status(rn, name="GET /status (after chat)")))

        tests.append(("GET /profile", lambda rn=round_num: self.test_profile(rn)))
        tests.append(("POST /contextsize", lambda rn=round_num: self.test_contextsize(rn)))
        tests.append(("POST /fetch", lambda rn=round_num: self.test_fetch(rn)))

        # textsplitter: /textsplitter + /v1/textsplitter
        for tp in ["/textsplitter", "/v1/textsplitter"]:
            tests.append((f"POST {tp}",
                          lambda rn=round_num, p=tp: self.test_textsplitter(rn, path=p)))

        # images: /images/generations + /v1/images/generations
        for ip in ["/images/generations", "/v1/images/generations"]:
            tests.append((f"POST {ip}",
                          lambda rn=round_num, p=ip: self.test_image_generate(rn, path=p)))

        # tool_calls / function calling 协议测试（与 -n 取值无关，覆盖 model/qnn/full 等主套件）：
        # 前两个是纯请求结构触发的确定性契约测试（不依赖模型真实决策），后两个是机会性观察，
        # 触发失败时优雅降级为 skipped=True，不计入 failed（见调查结论 Tab 第 9/10 节）。
        tests.append(("POST /v1/chat/completions (tool_call long history accepted)",
                      lambda rn=round_num: self.test_tool_call_long_history_accepted(rn)))
        tests.append(("POST /v1/chat/completions (tool_call round-trip with result)",
                      lambda rn=round_num: self.test_tool_call_round_trip_with_result(rn)))
        tests.append(("POST /v1/chat/completions (tool_call model invocation probe)",
                      lambda rn=round_num: self.test_tool_call_model_invocation_probe(rn)))
        tests.append(("POST /v1/chat/completions (tool_call streaming argument integrity probe)",
                      lambda rn=round_num: self.test_tool_call_streaming_argument_integrity_probe(rn)))

        tests.append(("POST /reload", lambda rn=round_num: self.test_reload(rn)))

        results = self._run_test_list(tests, round_num)
        if include_final_cleanup and round_num >= self.total_rounds:
            results.extend(self.run_final_cleanup(round_num))
        return results

    def _run_test_list(self, tests, round_num):
        """遍历一组 (name, fn) 用例,统一处理重启限流、打印与结果收集。run_all()/
        run_multimodal_rounds()/run_final_cleanup() 共用这段循环体,避免重复维护
        同一套 is_over_restart_limit()/_classify_process_down() 处理逻辑。"""
        results = []
        for test_name, test_fn in tests:
            if self.is_over_restart_limit():
                # 按分类A/B/真实错误规则判定,不再用"gguf"/"mnn"/"gpu"关键字统一豁免。
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                results.append(TestResult(
                    name=test_name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"跳过：服务多次崩溃; {classify_detail}", crashed=True, skipped=True,
                    ignorable=ignorable,
                    ignore_reason=ignore_reason
                ))
                continue
            print(f"    [{round_num}] 测试 {test_name} ... ", end="", flush=True)
            result = test_fn()
            # 不再有"一次探测代表一整轮"的批量覆盖逻辑：每个测试方法自己的 passed/ignorable/
            # ignore_reason 判定（基于状态码 + 错误信息/failure_reason 等精确信号）就是最终结果，
            # 不会被这里的外部探测结论重新覆盖。
            # 打印顺序：PASS > CRASH > SKIP > IGN > FAIL——之前这里缺少 SKIP 分支，会把
            # 真正 skipped=True（如模型能力局限导致的机会性用例跳过、MNN 内存不足优雅拒绝）
            # 的结果误显示为 "✗ FAIL"，容易让人误判为真实回归；results.json/报告里的
            # TestResult.skipped 字段本身不受影响，这里只是修正控制台展示与其保持一致。
            status = ("✓ PASS" if result.passed else
                      ("✗ CRASH" if result.crashed else
                       ("⚠ SKIP" if result.skipped else
                        ("⚠ IGN" if result.ignorable else "✗ FAIL"))))
            print(f"{status} ({result.latency_ms:.0f}ms)")
            results.append(result)
        return results

    def run_final_cleanup(self, round_num):
        """整个模型生命周期测试的收尾:stop → clear → unload。从 run_all() 中抽出,
        以便调用方能先跑完 run_multimodal_rounds() 再执行收尾,不受轮数解耦影响。"""
        tests = [
            ("POST /stop", lambda rn=round_num: self.test_stop(rn)),
            ("POST /clear", lambda rn=round_num: self.test_clear(rn)),
            ("POST /unload", lambda rn=round_num: self.test_unload(rn)),
        ]
        return self._run_test_list(tests, round_num)

    def _find_switch_partner(self):
        """从 self._all_models 中找一个与 self.model_name 同后端(同设备)的其它模型,
        作为触发同设备动态切换用的伙伴。确定性排序取第一个,方便复现;找不到返回 None。"""
        my_backend = infer_backend(self.model_name)[0]
        candidates = sorted(
            m for m in self._all_models
            if m != self.model_name and infer_backend(m)[0] == my_backend
        )
        return candidates[0] if candidates else None

    def test_dynamic_switch_multimodal_stability(self, round_num):
        """回归 error.md 记录的复现场景:同设备把模型从 self.model_name 动态切换到
        一个伙伴模型,再切回来发多模态请求。①对伙伴模型发纯文本请求触发同设备切出;
        ②对 self.model_name 发 OpenAI 风格图文请求,同时完成"切回原模型"与"多模态推理"。"""
        name = "POST /v1/chat/completions (dynamic switch + multimodal stability)"
        if "image" not in detect_modality(self.model_name):
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=True, status_code=0, latency_ms=0,
                detail="该模型不支持图片，跳过", skipped=True
            )
        partner = self._find_switch_partner()
        if partner is None:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=0,
                detail="未发现同后端的其它模型，无法构造切换场景",
                skipped=True, ignorable=True, ignore_reason="switch_partner_missing"
            )

        switch_body = {
            "model": partner,
            "messages": [{"role": "user", "content": "hi"}],
            "stream": False
        }
        switch_resp = self._safe_request("POST", "/v1/chat/completions", name, round_num,
                                          json=switch_body, request_context=f"switch_to={partner}")
        if isinstance(switch_resp, TestResult):
            return switch_resp

        image_path = None
        if self.data_dir:
            preferred = self.data_dir / "img" / "1.png"
            if preferred.exists():
                image_path = preferred
        image_err = None
        if image_path is None:
            image_path, image_err = self._pick_random_asset("img", {".jpg", ".jpeg", ".png"})
        if image_path is None:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"素材缺失: {image_err}",
                skipped=True, ignorable=True, ignore_reason="data_dir 下 img 素材缺失"
            )
        ext = image_path.suffix.lower().lstrip(".")
        if ext == "jpg":
            ext = "jpeg"
        image_b64 = base64.b64encode(image_path.read_bytes()).decode("ascii")
        media_image_data_uri = f"data:image/{ext};base64,{image_b64}"
        prompt_text = random.choice(MULTIMODAL_PROMPTS)
        back_body = {
            "model": self.model_name,
            "messages": [
                {"role": "user", "content": [
                    {"type": "text", "text": prompt_text},
                    {"type": "image_url", "image_url": {"url": media_image_data_uri}}
                ]}
            ],
            "stream": False
        }
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=back_body,
                                   request_context=f"switch_back_to={self.model_name}, image={image_path.name}")
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        text_response = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                text_response = choices[0].get("message", {}).get("content", "") if choices else ""
                passed = len(text_response) > 0
            except Exception as e:
                text_response = f"JSON 解析失败: {e}"
        asset_detail = f"switch_partner={partner}, image={image_path.name}"
        detail = f"status={r.status_code}, {asset_detail}" if not passed else f"OK, {asset_detail}"
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            text_response=text_response, text_prompt=f"{prompt_text} [{asset_detail}]",
            media_image_data_uri=media_image_data_uri, media_asset_label=asset_detail
        )

    def run_multimodal_rounds(self):
        """独立于 run_all() 的多模态测试轮次,由 self.multimodal_rounds 驱动
        (未显式传入 --multimodal_rounds 时跟随 --rounds,默认行为不变)。每一轮依次执行
        client-style / openai-style-image / openai-style-audio 三个既有用例,以及本次新增的
        动态切换稳定性用例(self._all_models 非空时才追加),四个用例共享同一 mm_round 编号,
        各自重新随机抽取素材,抽取次数等于 self.multimodal_rounds。"""
        if not detect_modality(self.model_name):
            return []
        results = []
        for mm_round in range(1, self.multimodal_rounds + 1):
            tests = [
                ("POST /v1/chat/completions (multimodal client-style)",
                 lambda rn=mm_round: self.test_chat_multimodal_client_style(rn)),
                ("POST /v1/chat/completions (multimodal openai-style)",
                 lambda rn=mm_round: self.test_chat_multimodal_openai_style(rn)),
                ("POST /v1/chat/completions (multimodal audio openai-style)",
                 lambda rn=mm_round: self.test_chat_multimodal_audio_openai_style(rn)),
            ]
            if self._all_models:
                tests.append(("POST /v1/chat/completions (dynamic switch + multimodal stability)",
                              lambda rn=mm_round: self.test_dynamic_switch_multimodal_stability(rn)))
            results.extend(self._run_test_list(tests, mm_round))
        return results

    def test_welcome(self, round_num):
        resp = self._safe_request("GET", "/", "GET /", round_num)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = r.status_code == 200 and "text/html" in r.headers.get("content-type", "")
        return TestResult(
            name="GET /", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency,
            detail="OK" if passed else f"status={r.status_code}, content-type={r.headers.get('content-type','')}"
        )

    def test_models(self, round_num, path="/models"):
        # 该接口与模型无关，连续多次调用，任一失败即判失败；全部成功才 OK
        name = f"GET {path}"
        attempts = 3
        last_status = 0
        last_latency = 0.0
        last_response_data = {}
        fail_reason = ""
        for i in range(attempts):
            resp = self._safe_request("GET", path, name, round_num)
            if isinstance(resp, TestResult):
                resp.name = name
                resp.detail = f"attempt {i+1}/{attempts}: {resp.detail}"
                return resp
            r, latency = resp
            last_status = r.status_code
            last_latency = latency
            ok = False
            if r.status_code == 200:
                try:
                    data = r.json()
                    if "data" in data and isinstance(data["data"], list):
                        ok = True
                        models_list = data["data"]
                        last_response_data = {
                            "object": data.get("object", ""),
                            "count": len(models_list),
                            "models": [
                                {
                                    "id": m.get("id", ""),
                                    "is_loaded": m.get("is_loaded", None),
                                    "context_length": m.get("context_length", None),
                                    "backend": m.get("backend", ""),
                                    "device": m.get("device", ""),
                                }
                                for m in models_list
                            ]
                        }
                    else:
                        fail_reason = f"attempt {i+1}/{attempts}: 缺少 data 数组"
                except Exception as e:
                    fail_reason = f"attempt {i+1}/{attempts}: JSON 解析失败: {e}"
            else:
                fail_reason = f"attempt {i+1}/{attempts}: status={r.status_code}"
            if not ok:
                return TestResult(
                    name=name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=last_status, latency_ms=last_latency,
                    detail=fail_reason, response_data=last_response_data
                )
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=True, status_code=last_status, latency_ms=last_latency,
            detail=f"OK ({attempts}/{attempts} attempts)", response_data=last_response_data
        )

    def test_v1_models(self, round_num):
        # 委托给 test_models 的别名 /v1/models 调用
        return self.test_models(round_num, path="/v1/models")

    def test_status(self, round_num, name="GET /status"):
        # /status 是 GET 路由,不能用 POST
        # 严格判定:仅当 HTTP 200 且返回体含 loading 字段时 PASS;
        # 其它任何状态(包括服务端冷启动 set_content(json_object) type_error 触发的 400)
        # 一律视为 FAIL,在报告里直接暴露服务端缺陷。
        resp = self._safe_request("GET", "/status", name, round_num)
        if isinstance(resp, TestResult):
            resp.name = name
            return resp
        r, latency = resp
        passed = False
        detail = ""
        response_data = {}
        if r.status_code == 200:
            try:
                data = r.json()
                # FetchModelStatus 返回: {"loading": "0"或"1"}（字符串类型）
                if "loading" in data:
                    passed = True
                    loading_val = data.get("loading")
                    response_data = {"loading": loading_val}
                    detail = f"OK (loading={loading_val})"
                else:
                    detail = "FAIL: 200 但缺少 loading 字段"
                    response_data = data
            except Exception as e:
                detail = f"FAIL: JSON 解析失败: {e}, body={r.text[:100]}"
                response_data = {"raw_body": r.text[:200]}
        else:
            # 包括 400 (服务端 set_content type_error bug)、503 等
            try:
                response_data = r.json()
            except Exception:
                response_data = {"raw_body": r.text[:200] if r.text else ""}
            detail = f"FAIL: status={r.status_code}, body={r.text[:120] if r.text else ''}"
        # 已知缺陷: HTTP 400 + body 含 "invalid json" 是服务端 FetchModelStatus 把
        # nlohmann::json::object_t 直接塞进 httplib::Response::set_content 触发的 type_error,
        # 框架兜底回 400 + {"error":"invalid json"}。这是稳定可复现的占位实现缺陷,
        # 不影响其它接口,因此标记为可忽略。
        ignorable = False
        ignore_reason = ""
        if not passed and r.status_code == 400 and isinstance(response_data, dict) \
                and "invalid json" in str(response_data.get("error", "")).lower():
            ignorable = True
            ignore_reason = "服务端 /status 已知 type_error 缺陷 (set_content 收到 json_object 而非 string)"
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data,
            ignorable=ignorable, ignore_reason=ignore_reason
        )

    def test_profile(self, round_num):
        resp = self._safe_request("GET", "/profile", "GET /profile", round_num)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        # 严格判定：只有 200 + 非空 JSON body 才是 PASS。
        # "200 但 body 为空" 这一分支服务端已修复（见 chat_request_handler.cpp::FetchProfile），
        # 不应再出现；服务端现在会在 profile 数据未就绪时显式返回
        # 503 + {"reason": "no_profile_data"}，与"真正无模型加载"的 503 区分开。
        passed = False
        skipped = False
        detail = ""
        response_data = {}
        if r.status_code == 200:
            body_len = len(r.text.strip())
            if body_len > 0:
                try:
                    data = r.json()
                    passed = True
                    # 完整记录 profile 返回的 JSON 数据
                    response_data = data
                    detail = f"OK (keys={list(data.keys())[:8]})"
                except Exception:
                    detail = f"OK (非 JSON, body_len={body_len})"
                    response_data = {"raw_body": r.text[:500]}
            else:
                detail = "FAIL: 200 但 body 为空 (服务端契约缺陷回归)"
        elif r.status_code == 503:
            try:
                response_data = r.json()
            except Exception:
                response_data = {}
            reason = response_data.get("reason") if isinstance(response_data, dict) else None
            error_msg = str(response_data.get("error", "")) if isinstance(response_data, dict) else ""
            if reason == "no_profile_data":
                # profile 数据尚未生成（推理尚未真正开始）是环境/时序性质的场景，
                # 不是确定性契约缺陷；服务端已优雅提示，归类为 skipped 而非 failed。
                skipped = True
                detail = "SKIP: 服务端已优雅提示 profile 未就绪 (reason=no_profile_data)"
            elif "no model loaded" in error_msg.lower():
                if _is_cascading_mnn_oom(self.svc, self.model_name):
                    skipped = True
                    detail = "SKIP: 服务端因内存不足从未成功加载该模型,级联到 /profile(同一 MNN OOM 事件)"
                else:
                    detail = "FAIL: 503 无模型加载"
            else:
                detail = f"FAIL: 503 (未识别的 body: {response_data})"
        else:
            detail = f"FAIL: status={r.status_code}"
            try:
                response_data = r.json()
            except Exception:
                response_data = {"raw_body": r.text[:200]} if r.text else {}
        return TestResult(
            name="GET /profile", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data, skipped=skipped
        )

    def test_chat_non_stream(self, round_num, prompt, path="/v1/chat/completions", content_format="openai_string"):
        perf_before = self.perf.snapshot()
        name = f"POST {path} (non-stream)"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": _build_chat_system_content(content_format)},
                {"role": "user", "content": _build_chat_content(prompt, content_format)}
            ],
            "stream": False
        }
        log_offset = self._capture_log_offset()
        resp = self._safe_request("POST", path,
                                  name, round_num,
                                  json=body)
        perf_after = self.perf.snapshot()
        if isinstance(resp, TestResult):
            resp.name = name
            resp.text_prompt = prompt
            resp.perf_before = perf_before
            resp.perf_after = perf_after
            resp.request_format = content_format
            return resp
        r, latency = resp
        passed = False
        skipped = False
        text_response = ""
        detail = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                if choices and "message" in choices[0] and "content" in choices[0]["message"]:
                    text_response = choices[0]["message"]["content"]
                    passed = len(text_response) > 0
                    detail = f"response_len={len(text_response)}"
                else:
                    detail = "缺少 choices[0].message.content"
            except Exception as e:
                detail = f"JSON 解析失败: {e}"
        else:
            detail = f"status={r.status_code}"
            failure_reason, failure_detail = (None, None)
            if r.status_code == 500:
                failure_reason, failure_detail = _extract_failure_reason(r)
            if failure_reason == "insufficient_memory":
                # 服务端优雅拒绝(MNN 内存预检查): 这是环境资源约束,不是代码缺陷,
                # 计为 skipped 而非 failed(不再计入失败统计),把具体的 failure_detail
                # 记进 detail 方便定位。
                skipped = True
                detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
            else:
                try:
                    detail += f" body={r.text[:200]}"
                except Exception:
                    pass

        # 模型缺陷标记(以服务端日志为准)：只扫描本次请求发出后新增的日志内容,查找
        # genie.cpp/genie_interface.cpp 记录的 [MODEL_DEFECT] 标记(context 超限但已优雅
        # 返回已生成内容的场景)。命中不算失败(HTTP 层面已是正常的 200/finish_reason=length),
        # 只作为模型输出质量的诊断信息附加在结果上。
        defect = _scan_model_defect_log(log_offset[0], log_offset[1]) if log_offset else None
        capability_issue, capability_reason = _capability_issue_from_model_defect(defect)

        return TestResult(
            name=name, round_num=round_num,
            model_name=self.model_name, passed=passed, status_code=r.status_code,
            latency_ms=latency, detail=detail, text_response=text_response,
            text_prompt=prompt, is_stream=False, skipped=skipped,
            perf_before=perf_before, perf_after=perf_after,
            request_format=content_format,
            model_capability_issue=capability_issue,
            model_capability_reason=capability_reason
        )

    # requests 的 timeout 对流式响应只约束"两次数据到达之间的间隔"，只要服务端持续
    # (哪怕很慢)吐出数据，读取循环本身没有总时长上限；这里加一个总时长兜底，
    # 超过该时长即主动 /stop 截断并记为失败，避免单个用例无限期占用整个回归的时间。
    MAX_STREAM_SECONDS = 300

    def test_chat_stream(self, round_num, prompt, path="/v1/chat/completions", content_format="openai_string"):
        perf_before = self.perf.snapshot()
        name = f"POST {path} (stream)"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": _build_chat_system_content(content_format)},
                {"role": "user", "content": _build_chat_content(prompt, content_format)}
            ],
            "stream": True
        }
        url = f"{self.base_url}{path}"
        start_time = time.time()
        ttft = 0.0
        chunk_count = 0
        full_response = ""
        got_done = False
        passed = False
        detail = ""
        stream_timeout = False

        if not self.svc.is_alive():
            if self._restart_count >= self.MAX_RESTARTS:
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=name, round_num=round_num,
                    model_name=self.model_name, passed=False, status_code=0, latency_ms=0,
                    detail=f"服务已崩溃且超过最大重启次数; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    text_prompt=prompt, is_stream=True, request_format=content_format
                )
            self.crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(), model_name=self.model_name,
                round_num=round_num, endpoint=name,
                detail="请求前检测到进程已退出",
                log_tail=_capture_log_tail(self.svc)
            ))
            self._restart_count += 1
            if not self.svc.restart():
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=name, round_num=round_num,
                    model_name=self.model_name, passed=False, status_code=0, latency_ms=0,
                    detail=f"服务重启失败; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    text_prompt=prompt, is_stream=True, request_format=content_format
                )

        log_offset = self._capture_log_offset()
        try:
            r = requests.post(url, json=body, stream=True, timeout=300)
            if r.status_code != 200:
                latency = (time.time() - start_time) * 1000
                perf_after = self.perf.snapshot()
                detail = f"status={r.status_code}"
                stream_skipped = False
                if r.status_code == 500:
                    failure_reason, failure_detail = _extract_failure_reason(r)
                    if failure_reason == "insufficient_memory":
                        # 服务端优雅拒绝(MNN 内存预检查): 环境资源约束,不是代码缺陷,
                        # 计为 skipped 而非 failed。
                        stream_skipped = True
                        detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
                        if infer_backend(self.model_name)[0] == "mnn":
                            _mark_mnn_oom(self.svc, self.model_name, detail)
                return TestResult(
                    name=name, round_num=round_num,
                    model_name=self.model_name, passed=False, status_code=r.status_code,
                    latency_ms=latency, detail=detail, skipped=stream_skipped,
                    text_prompt=prompt, is_stream=True,
                    perf_before=perf_before, perf_after=perf_after, request_format=content_format
                )

            for line in r.iter_lines(decode_unicode=True):
                if line is None:
                    continue
                line = line.strip()
                if not line:
                    continue
                if line.startswith("data:"):
                    data_str = line[5:].strip()
                    if data_str == "[DONE]":
                        got_done = True
                        break
                    try:
                        chunk_data = json.loads(data_str)
                        choices = chunk_data.get("choices", [])
                        if choices:
                            delta = choices[0].get("delta", {})
                            content = delta.get("content", "")
                            if content:
                                if chunk_count == 0:
                                    ttft = (time.time() - start_time) * 1000
                                chunk_count += 1
                                full_response += content
                    except json.JSONDecodeError:
                        pass
                if time.time() - start_time > self.MAX_STREAM_SECONDS:
                    stream_timeout = True
                    break

            if stream_timeout:
                try:
                    r.close()
                except Exception:
                    pass
                requests.post(f"{self.base_url}/stop", json={"text": "stop"}, timeout=15)

            latency = (time.time() - start_time) * 1000
            perf_after = self.perf.snapshot()
            if stream_timeout:
                passed = False
                detail = (f"流式响应超过总时长上限({self.MAX_STREAM_SECONDS}s),已主动 /stop 截断,"
                          f"chunks={chunk_count}, response_len={len(full_response)}")
            else:
                passed = got_done and len(full_response) > 0
                detail = f"chunks={chunk_count}, ttft={ttft:.0f}ms, response_len={len(full_response)}, done={got_done}"

        except (requests.ConnectionError, requests.Timeout) as e:
            latency = (time.time() - start_time) * 1000
            perf_after = self.perf.snapshot()
            # 带短暂宽限期重试确认进程是否真的已死,避免把真正致死的这次流式请求误判为
            # "进程仍存活的普通异常",而让后续某个无关请求背了这次崩溃的锅。
            if _confirm_process_dead(self.svc):
                is_mnn = infer_backend(self.model_name)[0] == "mnn"
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(), model_name=self.model_name,
                    round_num=round_num, endpoint=name,
                    detail=f"流式请求中服务崩溃: {type(e).__name__}; {classify_detail}",
                    log_tail=_capture_log_tail(self.svc)
                ))
                self._restart_count += 1
                restarted = False
                if self._restart_count <= self.MAX_RESTARTS:
                    restarted = self.svc.restart()
                if is_mnn and restarted:
                    self.crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(), model_name=self.model_name,
                        round_num=round_num, endpoint="MNN_OOM_CRASH",
                        detail=f"MNN OOM 崩溃后已自动重启(第{self._restart_count}次)",
                        log_tail=_capture_log_tail(self.svc)
                    ))
                elif ignore_reason == "mnn_oom_cascade":
                    self.crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(), model_name=self.model_name,
                        round_num=round_num, endpoint="MNN_OOM_CASCADE",
                        detail=classify_detail,
                        log_tail=_capture_log_tail(self.svc)
                    ))
                return TestResult(
                    name=name, round_num=round_num,
                    model_name=self.model_name, passed=False, status_code=0, latency_ms=latency,
                    detail=f"流式请求中服务崩溃: {e}; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    text_prompt=prompt, text_response=full_response, is_stream=True,
                    ttft_ms=ttft, chunk_count=chunk_count,
                    perf_before=perf_before, perf_after=perf_after, request_format=content_format
                )
            detail = f"请求异常: {type(e).__name__}: {e}"
            perf_after = self.perf.snapshot()
            return TestResult(
                name=name, round_num=round_num,
                model_name=self.model_name, passed=False, status_code=0, latency_ms=latency,
                detail=detail, text_prompt=prompt, text_response=full_response, is_stream=True,
                ttft_ms=ttft, chunk_count=chunk_count,
                perf_before=perf_before, perf_after=perf_after, request_format=content_format
            )

        # 模型缺陷标记(以服务端日志为准)：只扫描本次请求发出后新增的日志内容,查找
        # genie.cpp/genie_interface.cpp 记录的 [MODEL_DEFECT] 标记(context 超限但已优雅
        # 结束流式响应的场景)。命中不算失败,只作为模型输出质量的诊断信息附加在结果上。
        defect = _scan_model_defect_log(log_offset[0], log_offset[1]) if log_offset else None
        capability_issue, capability_reason = _capability_issue_from_model_defect(defect)

        return TestResult(
            name=name, round_num=round_num,
            model_name=self.model_name, passed=passed, status_code=200,
            latency_ms=latency, detail=detail, text_response=full_response,
            text_prompt=prompt, is_stream=True, ttft_ms=ttft, chunk_count=chunk_count,
            perf_before=perf_before, perf_after=perf_after,
            request_format=content_format,
            model_capability_issue=capability_issue,
            model_capability_reason=capability_reason
        )

    def _pick_random_asset(self, subdir, extensions):
        """从 data_dir/subdir 素材池中随机抽取一个文件（每次调用重新抽取，不缓存）。
        返回 (Path, None) 或 (None, 原因字符串)。委托给模块级 _pick_random_asset_file，
        与 run_sampleapp_only_tests 共用同一段筛选逻辑（保证两处用的是完全一致的素材池语义）。"""
        return _pick_random_asset_file(self.data_dir, subdir, extensions)

    def test_chat_multimodal_client_style(self, round_num):
        """GenieAPIClient 风格多模态请求（对应 ModelInputBuilder::ProcessObject）：
        content 为 {question, image, audio} object。每次从 data_dir/img、data_dir/audio
        素材池中随机抽取一个文件（不固定、不缓存），抽中的文件名记入 detail 方便复现。"""
        name = "POST /v1/chat/completions (multimodal client-style)"
        modality = detect_modality(self.model_name)
        image_path, image_err = (self._pick_random_asset("img", {".jpg", ".jpeg", ".png"})
                                  if "image" in modality else (None, None))
        audio_path, audio_err = (self._pick_random_asset("audio", {".wav"})
                                  if "audio" in modality else (None, None))
        if ("image" in modality and image_path is None) or ("audio" in modality and audio_path is None):
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"素材缺失: image_err={image_err}, audio_err={audio_err}",
                skipped=True, ignorable=True, ignore_reason="data_dir 下 img/audio 素材缺失"
            )

        image_b64 = base64.b64encode(image_path.read_bytes()).decode("ascii") if image_path else ""
        audio_b64 = base64.b64encode(audio_path.read_bytes()).decode("ascii") if audio_path else ""
        prompt_text = random.choice(MULTIMODAL_PROMPTS)
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": "You are a helpful assistant."},
                {"role": "user", "content": {
                    "question": prompt_text,
                    "image": image_b64,
                    "audio": audio_b64
                }}
            ],
            "stream": False
        }
        # 上面 body 里的 image/audio 是未带 data URI 前缀的裸 base64(GenieAPIClient 对象风格自己的
        # 协议),这里另外构造一份带 data URI 前缀的副本专用于 conversations.html 直接渲染
        # <img>/<audio>,不影响实际发给服务端的请求体。
        image_ext = image_path.suffix.lower().lstrip(".") if image_path else ""
        if image_ext == "jpg":
            image_ext = "jpeg"
        audio_ext = audio_path.suffix.lower().lstrip(".") if audio_path else ""
        media_image_data_uri = f"data:image/{image_ext};base64,{image_b64}" if image_path else ""
        media_audio_data_uri = f"data:audio/{audio_ext};base64,{audio_b64}" if audio_path else ""
        request_context = f"image={image_path.name if image_path else '-'}, audio={audio_path.name if audio_path else '-'}"
        log_offset = self._capture_log_offset()
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body, request_context=request_context)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        text_response = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                text_response = choices[0].get("message", {}).get("content", "") if choices else ""
                passed = len(text_response) > 0
            except Exception as e:
                text_response = f"JSON 解析失败: {e}"
        asset_detail = request_context
        detail = f"status={r.status_code}, {asset_detail}" if not passed else f"OK, {asset_detail}"
        defect = _scan_model_defect_log(log_offset[0], log_offset[1]) if log_offset else None
        capability_issue, capability_reason = _capability_issue_from_model_defect(defect)
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            text_response=text_response, text_prompt=f"{prompt_text} [{asset_detail}]",
            media_image_data_uri=media_image_data_uri, media_audio_data_uri=media_audio_data_uri,
            media_asset_label=asset_detail,
            model_capability_issue=capability_issue,
            model_capability_reason=capability_reason
        )

    def test_chat_multimodal_openai_style(self, round_num):
        """OpenAI 标准风格多模态请求（对应 ModelInputBuilder::ProcessArray）：
        content 为 [{type:text}, {type:image_url}] 数组，image_url 使用 data URI base64。
        音频的 OpenAI 风格覆盖见 test_chat_multimodal_audio_openai_style。"""
        name = "POST /v1/chat/completions (multimodal openai-style)"
        modality = detect_modality(self.model_name)
        if "image" not in modality:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=True, status_code=0, latency_ms=0,
                detail="该模型不支持图片，跳过", skipped=True
            )
        image_path, image_err = self._pick_random_asset("img", {".jpg", ".jpeg", ".png"})
        if image_path is None:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"素材缺失: {image_err}",
                skipped=True, ignorable=True, ignore_reason="data_dir 下 img 素材缺失"
            )
        ext = image_path.suffix.lower().lstrip(".")
        if ext == "jpg":
            ext = "jpeg"
        image_b64 = base64.b64encode(image_path.read_bytes()).decode("ascii")
        prompt_text = random.choice(MULTIMODAL_PROMPTS)
        media_image_data_uri = f"data:image/{ext};base64,{image_b64}"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "user", "content": [
                    {"type": "text", "text": prompt_text},
                    {"type": "image_url", "image_url": {"url": media_image_data_uri}}
                ]}
            ],
            "stream": False
        }
        log_offset = self._capture_log_offset()
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body,
                                   request_context=f"image={image_path.name}")
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        text_response = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                text_response = choices[0].get("message", {}).get("content", "") if choices else ""
                passed = len(text_response) > 0
            except Exception as e:
                text_response = f"JSON 解析失败: {e}"
        detail = f"status={r.status_code}, image={image_path.name}" if not passed else f"OK, image={image_path.name}"
        defect = _scan_model_defect_log(log_offset[0], log_offset[1]) if log_offset else None
        capability_issue, capability_reason = _capability_issue_from_model_defect(defect)
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            text_response=text_response, text_prompt=f"{prompt_text} [image={image_path.name}]",
            media_image_data_uri=media_image_data_uri, media_asset_label=f"image={image_path.name}",
            model_capability_issue=capability_issue,
            model_capability_reason=capability_reason
        )

    def test_chat_multimodal_audio_openai_style(self, round_num):
        """OpenAI 标准风格音频多模态请求（对应 ModelInputBuilder::ProcessArray）：
        content 为 [{type:text}, {type:input_audio}] 数组，input_audio.data 为 base64 音频数据。"""
        name = "POST /v1/chat/completions (multimodal audio openai-style)"
        modality = detect_modality(self.model_name)
        if "audio" not in modality:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=True, status_code=0, latency_ms=0,
                detail="该模型不支持音频，跳过", skipped=True
            )
        audio_path, audio_err = self._pick_random_asset("audio", {".wav"})
        if audio_path is None:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"素材缺失: {audio_err}",
                skipped=True, ignorable=True, ignore_reason="data_dir 下 audio 素材缺失"
            )
        audio_format = audio_path.suffix.lower().lstrip(".")
        audio_b64 = base64.b64encode(audio_path.read_bytes()).decode("ascii")
        prompt_text = random.choice(MULTIMODAL_PROMPTS)
        media_audio_data_uri = f"data:audio/{audio_format};base64,{audio_b64}"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "user", "content": [
                    {"type": "text", "text": prompt_text},
                    {"type": "input_audio", "input_audio": {"data": audio_b64, "format": audio_format}}
                ]}
            ],
            "stream": False
        }
        log_offset = self._capture_log_offset()
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body,
                                   request_context=f"audio={audio_path.name}")
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        text_response = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                text_response = choices[0].get("message", {}).get("content", "") if choices else ""
                passed = len(text_response) > 0
            except Exception as e:
                text_response = f"JSON 解析失败: {e}"
        detail = f"status={r.status_code}, audio={audio_path.name}" if not passed else f"OK, audio={audio_path.name}"
        defect = _scan_model_defect_log(log_offset[0], log_offset[1]) if log_offset else None
        capability_issue, capability_reason = _capability_issue_from_model_defect(defect)
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            text_response=text_response, text_prompt=f"{prompt_text} [audio={audio_path.name}]",
            media_audio_data_uri=media_audio_data_uri, media_asset_label=f"audio={audio_path.name}",
            model_capability_issue=capability_issue,
            model_capability_reason=capability_reason
        )

    def test_textsplitter(self, round_num, path="/v1/textsplitter"):
        name = f"POST {path}"
        body = {
            "text": "Hello world. This is a test sentence for text splitting. It should return an array of content.",
            "max_length": 50,
            "separators": [".", " ", ""]
        }
        resp = self._safe_request("POST", path, name, round_num, json=body)
        if isinstance(resp, TestResult):
            resp.name = name
            return resp
        r, latency = resp
        passed = False
        skipped = False
        detail = ""
        response_data = {}
        if r.status_code == 200:
            try:
                data = r.json()
                passed = "content" in data and isinstance(data["content"], list)
                if passed:
                    content_list = data["content"]
                    detail = f"segments={len(content_list)}"
                    response_data = {
                        "object": data.get("object", ""),
                        "segment_count": len(content_list),
                        "segments": [
                            {"text": s.get("text", "")[:100], "length": s.get("length", 0)}
                            for s in content_list[:10]
                        ]
                    }
                else:
                    detail = "缺少 content 数组"
            except Exception as e:
                detail = f"JSON 解析失败: {e}"
        else:
            detail = f"status={r.status_code}"
            try:
                response_data = r.json()
            except Exception:
                pass
            if _is_cascading_mnn_oom(self.svc, self.model_name):
                skipped = True
                detail = f"SKIP: status={r.status_code},服务端因内存不足从未成功加载该模型,级联到 {path}(同一 MNN OOM 事件)"
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data, skipped=skipped
        )

    def test_contextsize(self, round_num):
        body = {"model": self.model_name}
        resp = self._safe_request("POST", "/contextsize", "POST /contextsize", round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        skipped = False
        detail = ""
        response_data = {}
        if r.status_code == 200:
            try:
                data = r.json()
                ctx = data.get("contextsize", 0)
                passed = ctx > 0
                detail = f"contextsize={ctx}"
                response_data = {"contextsize": ctx}
                if not passed and _is_cascading_mnn_oom(self.svc, self.model_name):
                    skipped = True
                    detail = f"SKIP: contextsize=0,服务端因内存不足从未成功加载该模型,级联到 /contextsize(同一 MNN OOM 事件)"
            except Exception as e:
                detail = f"JSON 解析失败: {e}"
        else:
            detail = f"status={r.status_code}"
            try:
                response_data = r.json()
            except Exception:
                pass
        return TestResult(
            name="POST /contextsize", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data, skipped=skipped
        )

    def test_stop(self, round_num):
        body = {"text": "stop"}
        resp = self._safe_request("POST", "/stop", "POST /stop", round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = r.status_code == 200
        return TestResult(
            name="POST /stop", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency,
            detail="OK" if passed else f"status={r.status_code}"
        )

    def test_clear(self, round_num):
        body = {"text": "clear"}
        resp = self._safe_request("POST", "/clear", "POST /clear", round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = r.status_code == 200
        return TestResult(
            name="POST /clear", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency,
            detail="OK" if passed else f"status={r.status_code}"
        )

    def test_fetch(self, round_num):
        body = {}
        resp = self._safe_request("POST", "/fetch", "POST /fetch", round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        detail = ""
        response_data = {}
        if r.status_code == 200:
            try:
                data = r.json()
                passed = "history" in data
                if passed:
                    history = data.get("history", [])
                    detail = f"history_len={len(history)}"
                    response_data = {"history_count": len(history), "history": history[:5]}
                else:
                    detail = "缺少 history 字段"
                    response_data = data
            except Exception as e:
                detail = f"JSON 解析失败: {e}"
        else:
            detail = f"status={r.status_code}"
        return TestResult(
            name="POST /fetch", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data
        )

    def test_reload(self, round_num):
        body = {"action": "import_history", "history": []}
        resp = self._safe_request("POST", "/reload", "POST /reload", round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        # 严格判定: 仅 200 视为 PASS;
        # 服务端目前会返回 400 "Not supported in stateless mode" - 直接判 FAIL。
        response_data = {}
        try:
            response_data = r.json()
        except Exception:
            response_data = {"raw_body": r.text[:200] if r.text else ""}
        if r.status_code == 200:
            passed = True
            detail = "OK"
        else:
            passed = False
            err = response_data.get("error") if isinstance(response_data, dict) else r.text[:80]
            detail = f"FAIL: status={r.status_code}, body={err}"
        # 已知缺陷: 服务端 ChatRequestHandler::ReloadMessage 是一个占位实现,
        # 永远返回 400 + {"error":"Not supported in stateless mode"}。
        # 没有任何分支,所以这条 FAIL 是稳定可复现的占位实现缺陷,标记为可忽略。
        ignorable = False
        ignore_reason = ""
        if not passed and r.status_code == 400 and isinstance(response_data, dict) \
                and "stateless mode" in str(response_data.get("error", "")).lower():
            ignorable = True
            ignore_reason = "服务端 /reload 为占位实现 (ChatRequestHandler::ReloadMessage 写死返回 400)"
        return TestResult(
            name="POST /reload", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data,
            ignorable=ignorable, ignore_reason=ignore_reason
        )

    def test_image_generate(self, round_num, path="/v1/images/generations"):
        # 严格判定: 仅 200 视为 PASS;
        # 服务端目前返回 501 (Not Implemented) - 严格策略下直接判 FAIL,暴露未实现状态。
        body = {"prompt": "a cat", "n": 1, "size": "256x256"}
        name = f"POST {path}"
        resp = self._safe_request("POST", path, name, round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        response_data = {}
        try:
            response_data = r.json()
        except Exception:
            response_data = {"raw_body": r.text[:200] if r.text else ""}
        passed = r.status_code == 200
        if passed:
            detail = "OK"
        else:
            detail = f"FAIL: status={r.status_code}, body={r.text[:120] if r.text else ''}"
        # 已知缺陷: /images/generations 在当前服务版本未实现,
        # 服务端直接返回 HTTP 501 Not Implemented。FAIL 但可忽略。
        ignorable = False
        ignore_reason = ""
        if not passed and r.status_code == 501:
            ignorable = True
            ignore_reason = "服务端 /images/generations 未实现 (HTTP 501 Not Implemented)"
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            response_data=response_data,
            ignorable=ignorable, ignore_reason=ignore_reason
        )

    def test_tool_call_long_history_accepted(self, round_num):
        """确定性契约测试：最后一条 user 消息之后紧跟 LONG_TOOL_HISTORY_COUNT 条 role:"tool"
        占位消息,断言服务端不按工具调用次数拒绝请求(返回 200,且响应体不含 tool_call_limit /
        "maximum allowed tool call retries")。服务端已不设工具调用次数上限,防死循环由客户端
        (Builder 无进展熔断)负责。"""
        name = "POST /v1/chat/completions (tool_call long history accepted)"
        tool_messages = [
            {"role": "tool", "tool_call_id": f"call_{i}", "name": "read",
             "content": "placeholder tool result for long-history probe"}
            for i in range(LONG_TOOL_HISTORY_COUNT)
        ]
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": "You are a helpful assistant."},
                {"role": "user", "content": "Please read the file and tell me its content."},
            ] + tool_messages,
            "stream": False
        }
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        skipped = False
        detail = f"status={r.status_code}"
        body_text = r.text or ""
        if r.status_code == 200:
            limit_hit = ("tool_call_limit" in body_text
                         or "maximum allowed tool call retries" in body_text)
            passed = not limit_hit
            detail = f"status=200, tool_messages={LONG_TOOL_HISTORY_COUNT}, limit_hit={limit_hit}"
        else:
            failure_reason, failure_detail = (None, None)
            if r.status_code == 500:
                failure_reason, failure_detail = _extract_failure_reason(r)
            if failure_reason == "insufficient_memory":
                # 服务端优雅拒绝(MNN 内存预检查): 环境资源约束,不是代码缺陷,计为 skipped。
                skipped = True
                detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
            else:
                try:
                    detail += f", tool_messages={LONG_TOOL_HISTORY_COUNT}, body={body_text[:200]}"
                except Exception:
                    pass
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail, skipped=skipped
        )

    def test_tool_call_round_trip_with_result(self, round_num):
        """确定性契约测试(Step 4)：手动构造两轮对话 —— user 提问 -> assistant 消息带
        tool_calls=[{"id":"call_1","type":"function","function":{"name":"read",
        "arguments":"{\\"path\\":...}"}}](使用预定义工具名"read",prompt_optimizer.cpp:705-727
        已确认存在) -> role:"tool" 带 tool_call_id+name+模拟文件内容 -> 追问 user,断言
        200 + choices[0].message.content 非空。验证服务端能正确解析回填的 tool 结果并继续
        生成,不因 tool_calls/tool_call_id 结构异常而 400/500/崩溃 —— 这条路径此前从未被
        任何测试请求过。只做"不崩溃 + 结构完整性"验证,不对模型追问后的回复内容做语义判分。"""
        name = "POST /v1/chat/completions (tool_call round-trip with result)"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": "You are a helpful assistant."},
                {"role": "user", "content": "Please check the content of README.md for me."},
                {"role": "assistant", "content": None, "tool_calls": [
                    {"id": "call_1", "type": "function",
                     "function": {"name": "read", "arguments": "{\"path\": \"README.md\"}"}}
                ]},
                {"role": "tool", "tool_call_id": "call_1", "name": "read",
                 "content": "This is a placeholder simulated file content used for testing purposes only."},
                {"role": "user", "content": "Thanks, please briefly acknowledge what you found."}
            ],
            "stream": False
        }
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = False
        skipped = False
        text_response = ""
        detail = ""
        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                if choices and "message" in choices[0] and "content" in choices[0]["message"]:
                    text_response = choices[0]["message"]["content"] or ""
                    passed = len(text_response) > 0
                    detail = f"response_len={len(text_response)}"
                else:
                    detail = "缺少 choices[0].message.content"
            except Exception as e:
                detail = f"JSON 解析失败: {e}"
        else:
            detail = f"status={r.status_code}"
            failure_reason, failure_detail = (None, None)
            if r.status_code == 500:
                failure_reason, failure_detail = _extract_failure_reason(r)
            if failure_reason == "insufficient_memory":
                # 服务端优雅拒绝(MNN 内存预检查): 环境资源约束,不是代码缺陷,计为 skipped。
                skipped = True
                detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
            else:
                try:
                    detail += f" body={r.text[:200]}"
                except Exception:
                    pass
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            skipped=skipped, text_response=text_response
        )

    def test_tool_call_model_invocation_probe(self, round_num):
        """机会性观察验证(Step 5)：用强指令 prompt 要求模型必须调用预定义工具"read"作答,
        并携带对应的 tools=[JSON Schema] 定义。若响应 finish_reason=="tool_calls":对
        choices[0].message.tool_calls 数组做结构性 schema 校验(id 非空字符串、
        type=="function"、function.name 非空、function.arguments 是可被 json.loads
        解析的合法 JSON 字符串),不判断参数取值语义。若模型未按指令触发 tool_calls
        (量化/小模型的真实可能性,非服务端缺陷):标记 skipped=True 并注明原因,不计入
        failed —— 与项目现有"不对 LLM 输出做语义打分"的测试哲学一致。"""
        name = "POST /v1/chat/completions (tool_call model invocation probe)"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": "You are a helpful assistant with access to tools."},
                {"role": "user", "content": (
                    "Call the function 'read' now with its 'path' argument set to the exact "
                    "literal value \"README.md\" (an actual value, not the function's parameter "
                    "schema/definition). Respond only with a tool call using the concrete "
                    "argument {\"path\": \"README.md\"}; do not describe or repeat the "
                    "function's schema, and do not respond in plain text."
                )}
            ],
            "tools": [_STATELESS_MODE_READ_TOOL_DEF],
            "stream": False
        }
        resp = self._safe_request("POST", "/v1/chat/completions", name, round_num, json=body)
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        if r.status_code != 200:
            detail = f"status={r.status_code}"
            skipped = False
            if r.status_code == 500:
                failure_reason, failure_detail = _extract_failure_reason(r)
                if failure_reason == "insufficient_memory":
                    skipped = True
                    detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
            if not skipped:
                try:
                    detail += f" body={r.text[:200]}"
                except Exception:
                    pass
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=r.status_code, latency_ms=latency, detail=detail, skipped=skipped
            )
        try:
            data = r.json()
            choices = data.get("choices", [])
            finish_reason = choices[0].get("finish_reason") if choices else None
            message = choices[0].get("message", {}) if choices else {}
            tool_calls = message.get("tool_calls")
        except Exception as e:
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=r.status_code, latency_ms=latency,
                detail=f"JSON 解析失败: {e}"
            )
        if finish_reason != "tool_calls" or not tool_calls:
            _reason = f"模型未按指令触发 tool_calls(finish_reason={finish_reason!r}),非服务端异常,不计入 failed"
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=r.status_code, latency_ms=latency,
                detail=_reason,
                skipped=True, model_capability_issue=True, model_capability_reason=_reason
            )
        # "unknow" 是服务端 ResponseTools::convertToolCallJson 对"无法解析模型输出为合法工具
        # 调用 JSON"的精确、已文档化的兜底标记(response_dispatcher.cpp 的畸形工具调用死循环
        # 检测机制正是围绕这个标记设计的,见调查结论 Tab 第9.2节)。曾经(Layer 1-3 兜底修复架构
        # 落地前)这是模型能力局限的容忍信号,但 Layer -1/0/1/2/3 架构(response_tools.cpp/
        # response_dispatcher.cpp,见同名 .md 文档)已确保:模型一旦真的触发了 tool_calls(本测试
        # 已在上面排除"未触发"情形),最终响应体永不应再出现 "unknow" 这个兜底占位符——
        # Layer1 本地确定性提取 + Layer2 服务端内部隐形自纠正重试 + Layer3 分级终态协议三层
        # 兜底会在模型输出畸形时收敛为"合法 tool_call(识别出真实工具名)"或"纯文本
        # (finish_reason=stop/length)"之一,不会再放行 "unknow" 走到客户端。因此一旦命中,
        # 判定为硬性失败(hard_errors),而不再是 skipped 容忍——这是本测试区别于"模型未触发
        # tool_calls"分支的关键:那种情形是模型指令遵循问题(服务端管不了),这种情形曾是服务端
        # 自身兜底链全部失败的信号(服务端该管、现已通过新架构管住)。
        if any(tc.get("function", {}).get("name") == "unknow" for tc in tool_calls):
            _reason = ("模型触发了 tool_calls 且服务端仍输出了 unknow 兜底工具名"
                       "(ResponseTools::convertToolCallJson 精确兜底标记)——Layer -1/0/1/2/3"
                       "兜底修复架构落地后不应再出现此标记,这是服务端契约回归,计入 failed")
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=r.status_code, latency_ms=latency,
                detail=_reason,
                skipped=False, response_data={"tool_calls": tool_calls, "finish_reason": finish_reason}
            )
        if finish_reason not in ("tool_calls", "stop", "length"):
            _reason = (f"finish_reason={finish_reason!r} 不属于 tool_calls/stop/length 三者之一"
                       "——Layer -1/0/1/2/3 兜底架构下不应存在第四种半成品终态,计入 failed")
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=r.status_code, latency_ms=latency,
                detail=_reason,
                skipped=False, response_data={"tool_calls": tool_calls, "finish_reason": finish_reason}
            )
        # hard_errors：服务端确定性保证的结构字段——id/type 由 response_tools.cpp::format_tool_calls
        # 硬编码生成（generate_uuid4()/"function"字面量），function.name 有精确的 "unknow" 兜底标记
        # （已在上面处理），这三者出错才是真正的服务端契约缺陷。
        # soft_errors：function.arguments 的字符串内容是否能解析为合法 JSON，完全取决于模型自身
        # 输出质量——已用源码核实 convertToolCallJson（response_tools.cpp 第260-278行）在解析失败时
        # 会原样保留模型输出的字符串，这段内容不是服务端可控的确定性契约，因此不应计入 fail，
        # 而是降级为模型能力局限导致的 skip（与项目现有测试哲学一致：不因模型输出格式混乱而误判
        # 服务端缺陷）。
        hard_errors = []
        soft_errors = []
        for idx, tc in enumerate(tool_calls):
            tc_id = tc.get("id")
            if not isinstance(tc_id, str) or not tc_id:
                hard_errors.append(f"tool_calls[{idx}].id 非法: {tc_id!r}")
            if tc.get("type") != "function":
                hard_errors.append(f"tool_calls[{idx}].type != 'function': {tc.get('type')!r}")
            func = tc.get("function", {}) or {}
            fname = func.get("name")
            if not isinstance(fname, str) or not fname:
                hard_errors.append(f"tool_calls[{idx}].function.name 非法: {fname!r}")
            fargs = func.get("arguments")
            if not isinstance(fargs, str):
                hard_errors.append(f"tool_calls[{idx}].function.arguments 不是字符串: {type(fargs)}")
            else:
                try:
                    json.loads(fargs)
                except Exception as e:
                    soft_errors.append(f"tool_calls[{idx}].function.arguments 不是合法 JSON"
                                       f"(模型输出质量问题,非服务端契约缺陷): {e}")
        if hard_errors:
            passed, skipped, detail = False, False, "; ".join(hard_errors)
            capability_issue = False
        elif soft_errors:
            passed, skipped, detail = False, True, "; ".join(soft_errors)
            capability_issue = True
        else:
            passed, skipped, detail = True, False, "tool_calls schema 校验通过"
            capability_issue = False
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
            skipped=skipped, response_data={"tool_calls": tool_calls, "finish_reason": finish_reason},
            model_capability_issue=capability_issue, model_capability_reason=detail if capability_issue else ""
        )

    def test_tool_call_streaming_argument_integrity_probe(self, round_num):
        """预防性回归:用强指令 prompt 要求模型必须调用预定义工具"read"并携带一个足够长
        (120+字符)的 path 值,以 stream=true 发起请求,按 index 聚合全部流式 delta.tool_calls
        片段重建最终参数。判定标准只针对与内容无关的机制事实,不对模型复述的具体文字做
        逐字比较——模型能否一字不差地复述一段人造长字符串是无法穷举的模型能力问题,只作为
        观察记录(model_capability_issue),不参与 passed/failed:若聚合到的分片数>1(说明
        这次真的触发了跨 chunk 拼接),但拼接结果不是合法 JSON 或缺失 path 字段,才判定为
        真实的拼接缺陷(failed)；分片数<=1 时(本地 qnn/mnn/gguf 路径目前始终如此,已用抓包
        核实 tool_calls 参数整段一次性到达)则只要求结构完整,内容准确度降级为观察记录。
        若模型未按指令触发 tool_calls:标记 skipped=True,不计入 failed。"""
        name = "POST /v1/chat/completions (tool_call streaming argument integrity probe)"
        target_path = "very_long_simulated_probe_path_" + ("x" * 90) + "/README_INTEGRITY_PROBE.md"
        body = {
            "model": self.model_name,
            "messages": [
                {"role": "system", "content": "You are a helpful assistant with access to tools."},
                {"role": "user", "content": (
                    f"Call the function 'read' now with its 'path' argument set to the exact "
                    f"literal value \"{target_path}\" (an actual value, not the function's "
                    "parameter schema/definition). Respond only with a tool call using the "
                    f"concrete argument {{\"path\": \"{target_path}\"}}, reproduced character "
                    "for character with no truncation; do not describe or repeat the function's "
                    "schema, and do not respond in plain text."
                )}
            ],
            "tools": [_STATELESS_MODE_READ_TOOL_DEF],
            "stream": True
        }
        url = f"{self.base_url}/v1/chat/completions"
        start_time = time.time()

        # 与 _safe_request 一致的进程存活性前置检查(流式路径需要手写,无法直接复用 _safe_request)。
        if not self.svc.is_alive():
            if self._restart_count >= self.MAX_RESTARTS:
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"服务已崩溃且超过最大重启次数; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason
                )
            self.crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(), model_name=self.model_name,
                round_num=round_num, endpoint=name, detail="请求前检测到进程已退出",
                log_tail=_capture_log_tail(self.svc)
            ))
            self._restart_count += 1
            if not self.svc.restart():
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                return TestResult(
                    name=name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"服务重启失败; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason
                )

        finish_reason = None
        tool_call_frags = {}  # index -> {"id":..., "type":..., "name":..., "arguments": "" (拼接累积)}
        try:
            r = requests.post(url, json=body, stream=True, timeout=300)
            if r.status_code != 200:
                latency = (time.time() - start_time) * 1000
                detail = f"status={r.status_code}"
                skipped = False
                if r.status_code == 500:
                    failure_reason, failure_detail = _extract_failure_reason(r)
                    if failure_reason == "insufficient_memory":
                        skipped = True
                        detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
                        if infer_backend(self.model_name)[0] == "mnn":
                            _mark_mnn_oom(self.svc, self.model_name, detail)
                return TestResult(
                    name=name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=r.status_code, latency_ms=latency, detail=detail, skipped=skipped
                )

            for line in r.iter_lines(decode_unicode=True):
                if line is None:
                    continue
                line = line.strip()
                if not line:
                    continue
                if line.startswith("data:"):
                    data_str = line[5:].strip()
                    if data_str == "[DONE]":
                        break
                    try:
                        chunk_data = json.loads(data_str)
                    except json.JSONDecodeError:
                        continue
                    choices = chunk_data.get("choices", [])
                    if not choices:
                        continue
                    choice0 = choices[0]
                    if choice0.get("finish_reason") == "tool_calls":
                        finish_reason = "tool_calls"
                    delta = choice0.get("delta", {}) or {}
                    delta_tool_calls = delta.get("tool_calls")
                    if delta_tool_calls:
                        for pos, tc in enumerate(delta_tool_calls):
                            idx = tc.get("index", pos)
                            frag = tool_call_frags.setdefault(
                                idx, {"id": "", "type": "", "name": "", "arguments": ""})
                            if tc.get("id"):
                                frag["id"] = tc["id"]
                            if tc.get("type"):
                                frag["type"] = tc["type"]
                            func = tc.get("function") or {}
                            if func.get("name"):
                                frag["name"] = func["name"]
                            if func.get("arguments"):
                                frag["arguments"] += func["arguments"]
                                frag["arg_frag_count"] = frag.get("arg_frag_count", 0) + 1
                if time.time() - start_time > self.MAX_STREAM_SECONDS:
                    break
        except (requests.ConnectionError, requests.Timeout) as e:
            latency = (time.time() - start_time) * 1000
            if _confirm_process_dead(self.svc):
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, self.model_name)
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(), model_name=self.model_name,
                    round_num=round_num, endpoint=name,
                    detail=f"流式请求中服务崩溃: {type(e).__name__}; {classify_detail}",
                    log_tail=_capture_log_tail(self.svc)
                ))
                self._restart_count += 1
                if self._restart_count <= self.MAX_RESTARTS:
                    self.svc.restart()
                return TestResult(
                    name=name, round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=latency,
                    detail=f"流式请求中服务崩溃: {e}; {classify_detail}", crashed=True,
                    ignorable=ignorable, ignore_reason=ignore_reason
                )
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=0, latency_ms=latency,
                detail=f"请求异常: {type(e).__name__}: {e}"
            )

        latency = (time.time() - start_time) * 1000
        if finish_reason != "tool_calls" or not tool_call_frags:
            _reason = f"模型未按指令触发 tool_calls(finish_reason={finish_reason!r}),非服务端异常,不计入 failed"
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=200, latency_ms=latency,
                detail=_reason,
                skipped=True, model_capability_issue=True, model_capability_reason=_reason
            )
        # "unknow" 是服务端 ResponseTools::convertToolCallJson 对"无法解析模型输出为合法工具
        # 调用 JSON"的精确、已文档化的兜底标记(见调查结论 Tab 第9.2节)。命中该精确信号说明
        # 模型确实尝试了调用但输出畸形,这是模型自身能力/量化程度的真实局限,不是服务端缺陷,
        # 按与"未触发 tool_calls"同样的容忍策略处理为 skipped=True。
        if any(frag.get("name") == "unknow" for frag in tool_call_frags.values()):
            _reason = ("模型触发了 tool_calls 但输出畸形,服务端已归类为 unknow 工具名"
                       "(ResponseTools::convertToolCallJson 精确兜底标记),属模型能力局限,不计入 failed")
            return TestResult(
                name=name, round_num=round_num, model_name=self.model_name,
                passed=False, status_code=200, latency_ms=latency,
                detail=_reason,
                skipped=True, response_data={"tool_call_frags": tool_call_frags, "finish_reason": finish_reason},
                model_capability_issue=True, model_capability_reason=_reason
            )

        # 机制事实优先于内容准确度:分片数(arg_frag_count)>1 说明这次真的触发了跨 chunk
        # 拼接,此时若拼接结果连合法 JSON/path 字段都凑不出来,才是需要关注的真实拼接缺陷
        # (structural_errors,failed)。分片数<=1 或拼接结果结构完整时,path 内容是否与指令
        # 目标逐字一致只作为观察记录(model_capability_issue),不影响 passed——模型对超长
        # 人造字符串的复述准确度是不可穷举的模型能力问题,不是服务端可控的确定性契约。
        json_parse_errors = []
        structural_errors = []
        no_path_notes = []
        content_mismatch_notes = []
        multi_fragment_detected = False
        matched_exactly = False
        for idx, frag in tool_call_frags.items():
            args_str = frag["arguments"]
            frag_count = frag.get("arg_frag_count", 0)
            if frag_count > 1:
                multi_fragment_detected = True
            try:
                parsed_args = json.loads(args_str)
            except Exception as e:
                if frag_count > 1:
                    structural_errors.append(f"tool_calls[index={idx}] 经历了 {frag_count} 个流式分片拼接,"
                                             f"但拼接结果不是合法 JSON(疑似跨 chunk 拼接丢字符): {e}")
                else:
                    json_parse_errors.append(f"tool_calls[index={idx}] arguments 不是合法 JSON"
                                             f"(模型输出质量问题,非服务端契约缺陷): {e}; raw_len={len(args_str)}")
                continue
            path_value = parsed_args.get("path")
            if path_value is None:
                if frag_count > 1:
                    structural_errors.append(f"tool_calls[index={idx}] 经历了 {frag_count} 个流式分片拼接,"
                                             f"但拼接结果里 path 字段缺失(疑似跨 chunk 拼接丢字符)")
                else:
                    no_path_notes.append(f"tool_calls[index={idx}] 未找到包含 path 字段的参数"
                                         f"(模型未按预期结构输出,非服务端异常)")
                continue
            if path_value == target_path:
                matched_exactly = True
            else:
                content_mismatch_notes.append(f"tool_calls[index={idx}] path 内容与指令目标不完全一致"
                                              f"(模型复述准确度问题,仅记录不影响判定): "
                                              f"got_len={len(path_value)}, expect_len={len(target_path)}")
        if structural_errors:
            passed, skipped, capability_issue = False, False, False
            detail = "; ".join(structural_errors)
        elif json_parse_errors:
            passed, skipped, capability_issue = False, True, True
            detail = "; ".join(json_parse_errors)
        elif no_path_notes and not matched_exactly and not content_mismatch_notes:
            passed, skipped, capability_issue = False, True, False
            detail = "; ".join(no_path_notes)
        else:
            passed, skipped = True, False
            frag_note = "经历多分片拼接" if multi_fragment_detected else "单分片一次性到达"
            if content_mismatch_notes:
                capability_issue = True
                detail = f"{frag_note},结构完整; " + "; ".join(content_mismatch_notes)
            else:
                capability_issue = False
                detail = f"{frag_note},重建后的 path 参数逐字符一致(len={len(target_path)})"
        return TestResult(
            name=name, round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=200, latency_ms=latency, detail=detail, skipped=skipped,
            response_data={"tool_call_frags": tool_call_frags, "finish_reason": finish_reason},
            model_capability_issue=capability_issue, model_capability_reason=detail if capability_issue else ""
        )

    def test_servicestop(self, round_num):
        """测试 POST /servicestop —— 该接口会使服务进程退出。
        只能在所有其它测试完成后调用一次。"""
        body = {"text": "stop"}
        # 为了避免 _safe_request 里面重启误杀，这里直接发请求。
        url = f"{self.base_url}/servicestop"
        start_time = time.time()
        passed = False
        response_data = {}
        try:
            r = requests.post(url, json=body, timeout=15)
            latency = (time.time() - start_time) * 1000
            try:
                response_data = r.json()
            except Exception:
                response_data = {"raw_body": r.text[:200] if r.text else ""}
            passed = r.status_code == 200
            detail = "OK" if passed else f"FAIL: status={r.status_code}"
            return TestResult(
                name="POST /servicestop", round_num=round_num, model_name=self.model_name,
                passed=passed, status_code=r.status_code, latency_ms=latency, detail=detail,
                response_data=response_data
            )
        except (requests.ConnectionError, requests.Timeout) as e:
            # 服务可能在返回响应前就差点关了 socket，这种情况认为 PASS（表示服务已退出），
            # 但明确报告为“连接在服务退出过程中被断开”。
            latency = (time.time() - start_time) * 1000
            time.sleep(2)
            if self.svc.is_alive():
                return TestResult(
                    name="POST /servicestop", round_num=round_num, model_name=self.model_name,
                    passed=False, status_code=0, latency_ms=latency,
                    detail=f"FAIL: 请求异常 {type(e).__name__}: {e}"
                )
            return TestResult(
                name="POST /servicestop", round_num=round_num, model_name=self.model_name,
                passed=True, status_code=0, latency_ms=latency,
                detail=f"OK (服务已退出; 连接在响应前被服务主动关闭: {type(e).__name__})"
            )

    def test_unload(self, round_num):
        resp = self._safe_request("POST", "/unload", "POST /unload", round_num, json={})
        if isinstance(resp, TestResult):
            return resp
        r, latency = resp
        passed = r.status_code == 200
        return TestResult(
            name="POST /unload", round_num=round_num, model_name=self.model_name,
            passed=passed, status_code=r.status_code, latency_ms=latency,
            detail="OK" if passed else f"status={r.status_code}"
        )

# ============================================================================
# ReportGenerator - 报告生成器
# ============================================================================
class ReportGenerator:
    @staticmethod
    def generate_json(all_results, perf_data, crash_events, out_dir):
        # ignored 是 failed 的子集 — 不是与 passed/failed/crashed 并列的第四种状态,
        # 而是"这些 failed 里有多少属于服务端已知缺陷,在过滤后可以忽略"。
        # 排查时,如果只关心真实回归,可以用 failed - ignored 看"非忽略失败数"。
        summary = {"total": 0, "passed": 0, "failed": 0, "crashed": 0, "skipped": 0, "ignored": 0,
                   "model_capability_issues": 0}
        models_data = {}

        for result in all_results:
            summary["total"] += 1
            if result.skipped:
                summary["skipped"] += 1
            elif result.crashed:
                summary["crashed"] += 1
            elif result.passed:
                summary["passed"] += 1
            else:
                summary["failed"] += 1
                if result.ignorable:
                    summary["ignored"] += 1
            if result.model_capability_issue:
                summary["model_capability_issues"] += 1

            model = result.model_name
            if model not in models_data:
                models_data[model] = {}
            rnd = f"round_{result.round_num}"
            if rnd not in models_data[model]:
                models_data[model][rnd] = []
            models_data[model][rnd].append({
                "name": result.name,
                "passed": result.passed,
                "status_code": result.status_code,
                "latency_ms": round(result.latency_ms, 1),
                "detail": result.detail,
                "crashed": result.crashed,
                "skipped": result.skipped,
                # 已知缺陷标记: ignorable=True 意味着这条 FAIL 是服务端已知占位/未实现缺陷,
                # 用于在统计、CI gate、报告过滤时区分"真实回归"vs"已知缺陷"。
                "ignorable": result.ignorable,
                "ignore_reason": result.ignore_reason if result.ignorable else None,
                "model_capability_issue": result.model_capability_issue,
                "model_capability_reason": result.model_capability_reason if result.model_capability_issue else None,
                "is_stream": result.is_stream,
                "ttft_ms": round(result.ttft_ms, 1) if result.is_stream else None,
                "chunk_count": result.chunk_count if result.is_stream else None,
                "text_prompt": result.text_prompt if result.text_prompt else None,
                "text_response": result.text_response if result.text_response else None,
                "response_data": result.response_data if result.response_data else None,
            })

        output = {
            "timestamp": datetime.now().isoformat(),
            "summary": summary,
            "models": models_data,
            "performance": perf_data,
            "crash_events": [asdict(e) for e in crash_events]
        }

        out_path = Path(out_dir) / "results.json"
        with open(out_path, "w", encoding="utf-8") as f:
            json.dump(output, f, indent=2, ensure_ascii=False)
        print(f"\n[输出] JSON 报告: {out_path}")

    # 模型无关接口（不需要加载模型即可测试的通用接口 + 全局收尾接口）
    MODEL_INDEPENDENT_ENDPOINTS = [
        "GET /", "GET /models", "GET /v1/models",
        "POST /servicestop",
    ]

    # 模型相关的所有端点(显式枚举,顺序即报告里的行序)
    MODEL_DEPENDENT_ENDPOINTS = [
        # /status 观察用,夹在 chat 前后
        "GET /status (before chat)",
        # ChatCompletions handler 注册的 4 个别名 × (non-stream + stream) = 8 项
        "POST /v1/chat/completions (non-stream)",
        "POST /v1/chat/completions (stream)",
        "POST /chat/completions (non-stream)",
        "POST /chat/completions (stream)",
        "POST /v1/completions (non-stream)",
        "POST /v1/completions (stream)",
        "POST /completions (non-stream)",
        "POST /completions (stream)",
        "GET /status (after chat)",
        # 其它模型相关 GET / POST
        "GET /profile",
        "POST /contextsize",
        "POST /fetch",
        # TextSplitter handler 两个别名
        "POST /textsplitter",
        "POST /v1/textsplitter",
        # ImageGenerate handler 两个别名
        "POST /images/generations",
        "POST /v1/images/generations",
        "POST /reload",
        # 最后一轮的收尾
        "POST /stop", "POST /clear", "POST /unload",
    ]

    # 推理性能相关(所有 chat 别名,任何一个有 perf 数据都纳入对比)
    MODEL_PERF_ENDPOINTS = [
        "POST /v1/chat/completions (non-stream)",
        "POST /v1/chat/completions (stream)",
        "POST /chat/completions (non-stream)",
        "POST /chat/completions (stream)",
        "POST /v1/completions (non-stream)",
        "POST /v1/completions (stream)",
        "POST /completions (non-stream)",
        "POST /completions (stream)",
        "GET /profile",
    ]

    # 内部占位 model_name：仅用于内部过滤/聚合（_global_=模型无关通用接口测试、
    # _multi_model_=阶段3多模型并发聚合、_builder_local_model_=QAIModelBuilderLocalModelTester
    # 里"不针对具体模型"的手段层检查项（仍被 skill_capacity 的 builder 模式复用），如
    # configure_genie_root/inject_local_models/discover_models_via_builder 等，_skill_capacity_ / _skill_capacity_builder_
    # =skill_capacity 套件里"整套件级/环境前置"的检查项，如两个目标模型都没匹配到时的
    # suite precondition），绝不能作为"模型名"文本渗透进任何
    # 渲染出的报告 HTML（性能对比表、模型链接卡片、标题等）。新增任何占位 model_name 时
    # 必须同步加入这里，并统一通过 _is_internal_placeholder_model() 过滤——排除逻辑必须
    # 统一走这个函数，不要分散在多处各自手写，否则容易遗漏。
    #
    # ⚠ 曾漏注册的实例（本机干跑渲染时被 _assert_no_placeholder_leak 之外的显式核验抓到）：
    # skill_capacity 套件的 _skill_capacity_ 系列占位名一度未登记，于是它作为"模型"渗进了
    # 主报告的模型链接卡片。新增套件时若引入了新的占位 model_name，务必同步登记到下面两个
    # 常量，否则防泄漏断言也扫不到它（该断言只认已登记的名字）。
    INTERNAL_PLACEHOLDER_MODEL_NAMES = frozenset({"_global_", "_multi_model_", "_builder_local_model_",
                                                  "_skill_capacity_"})
    INTERNAL_PLACEHOLDER_MODEL_PREFIXES = ("_graceful_shutdown_", "_skill_capacity_")

    @staticmethod
    def _is_internal_placeholder_model(model_name):
        """判断 model_name 是否为内部占位名（非真实模型），渲染报告时必须排除。"""
        return (model_name in ReportGenerator.INTERNAL_PLACEHOLDER_MODEL_NAMES
                or model_name.startswith(ReportGenerator.INTERNAL_PLACEHOLDER_MODEL_PREFIXES))

    @staticmethod
    def _assert_no_placeholder_leak(html, context):
        """防泄漏兜底：报告生成完毕、写盘之前，扫描最终 HTML 全文，确认内部占位
        model_name 没有被当作可读文本渗透进去。这是最后一道防线——即使某个渲染路径
        遗漏了 _is_internal_placeholder_model() 过滤，也会在这里立刻炸出来，而不是让
        "_multi_model_" 这类占位符悄悄流入 report.html 被人误以为是一个真实模型。"""
        for name in ReportGenerator.INTERNAL_PLACEHOLDER_MODEL_NAMES:
            if name in html:
                raise RuntimeError(
                    f"[占位符泄漏防护] 检测到内部占位 model_name {name!r} 以文本形式出现在"
                    f"生成的 HTML 中（{context}）。这不允许发生——请检查是否有渲染路径遗漏了"
                    f" ReportGenerator._is_internal_placeholder_model() 过滤。"
                )

    # "多类型同时加载"阶段的检查项名称（MULTI: 前缀）为内部实现层面的英文短语，对不熟悉
    # 代码的人偏抽象（如 "backend coexistence matrix (triple + pairwise fallback)"）。
    # 这里按"精确匹配的静态检查项"与"带动态后缀（模型名/组合名）的检查项"分两组维护
    # 说明文案，供 _generate_multi_backend_detail_html 的"逐项检查记录"表格渲染"说明"列。
    # 新增该阶段的检查项时应同步在此补充映射，否则该行"说明"列会留空。
    _MULTI_CHECK_DESCRIPTIONS_EXACT = {
        "MULTI: GET /models (multi-model list)":
            "调用 GET /models 接口，验证服务能正确返回当前已加载的模型",
        "MULTI: sequential backend switching (npu/gpu/cpu each independently loadable)":
            "依次向 QNN(NPU)/GGUF(GPU)/MNN(CPU) 三种后端各一个模型发送请求，验证 ModelManager::LoadModelByName() 的顺序单模型切换能力在三种后端间均能正常工作（不要求同时驻留，本仓库已删除并发多模型托管设计）",
        "MULTI: invalid model route returns 404/400":
            "请求一个不存在的模型名，验证服务能快速返回 404/400 错误，而不是长时间挂起或误路由到其它模型",
        "MULTI: concurrent requests to different models":
            "同时向多个已加载的不同模型并发发送请求，验证并发场景下各请求能被正确路由到对应模型、互不干扰、不引发崩溃（同时校验回复内容非空；单模型架构下通常因已加载模型 <2 个而被跳过）",
        "MULTI: default model route (no 'model' field) after dynamic switches":
            "发一个不带 model 字段的请求，观察在多次动态切换后默认模型是否仍能正常响应（当前实现里默认模型会随动态切换漂移，本检查只监控不崩溃/不返回 5xx，不假定具体路由到哪个模型）",
    }
    _MULTI_CHECK_DESCRIPTIONS_PREFIX = (
        ("MULTI: auto-restart after MNN OOM (",
         "MNN 模型因内存不足导致进程崩溃后，验证服务能否自动重启并恢复到可正常接受请求的状态"),
        ("MULTI: chat route → ",
         "向该模型发送一次 chat 请求，验证请求能被正确路由到此模型并返回正常响应"),
    )

    @staticmethod
    def _describe_multi_check(name):
        """把"多类型同时加载"阶段某条检查项的名称，翻译成一句人类可读的说明文字。
        精确匹配优先；未命中时再按已知前缀匹配带动态后缀（模型名/组合名）的检查项；
        两者都未命中返回空字符串（该行"说明"列留空，而不是报错阻断报告生成）。"""
        desc = ReportGenerator._MULTI_CHECK_DESCRIPTIONS_EXACT.get(name)
        if desc:
            return desc
        for prefix, prefix_desc in ReportGenerator._MULTI_CHECK_DESCRIPTIONS_PREFIX:
            if name.startswith(prefix):
                return prefix_desc
        return ""

    # "逐项检查记录"表格按类别分组展示，而不是把全部检查项摊成一张不分类的长列表——
    # 单模型路由验证("MULTI: chat route → <model>")会随已加载模型数量线性增长、逐条描述
    # 高度雷同，混在其它类别检查项中会显得杂乱且难以定位。每个元组为
    # (类别名, 精确匹配名称集合, 前缀匹配元组)；分类顺序即渲染顺序。新增检查项时应同步
    # 在此归类，未归类的检查项会落入下方 _MULTI_CHECK_CATEGORY_FALLBACK 兜底类别（不报错）。
    _MULTI_CHECK_CATEGORIES = (
        ("单模型路由验证", (), ("MULTI: chat route → ",)),
        ("多后端顺序切换验证", (
            "MULTI: sequential backend switching (npu/gpu/cpu each independently loadable)",
        ), ()),
        ("通用接口与异常路由", (
            "MULTI: GET /models (multi-model list)",
            "MULTI: invalid model route returns 404/400",
            "MULTI: default model route (no 'model' field) after dynamic switches",
        ), ()),
        ("并发与故障恢复", (
            "MULTI: concurrent requests to different models",
        ), ("MULTI: auto-restart after MNN OOM (",)),
    )
    _MULTI_CHECK_CATEGORY_FALLBACK = "其它检查项"

    @staticmethod
    def _categorize_multi_check(name):
        """把"多类型同时加载"阶段某条检查项的名称归入一个分组类别，用于"逐项检查记录"
        表格的分组展示。精确匹配优先；未命中时再按前缀匹配；两者都未命中归入统一的兜底
        类别（而不是报错阻断报告生成）。"""
        for category, exact_names, prefixes in ReportGenerator._MULTI_CHECK_CATEGORIES:
            if name in exact_names:
                return category
            for prefix in prefixes:
                if name.startswith(prefix):
                    return category
        return ReportGenerator._MULTI_CHECK_CATEGORY_FALLBACK

    @staticmethod
    def _common_css():
        """Professional dashboard aesthetic — Material-inspired blue header, soft-shadow cards, sans-serif body, tabular mono numbers. Mirrors the legacy report.html with subtle refinements."""
        return """:root {
    --primary: #1565C0;
    --primary-light: #1976D2;
    --primary-dark: #0D47A1;
    --accent: #1565C0;
    --success: #2E7D32;
    --success-light: #43A047;
    --danger: #C62828;
    --danger-light: #E53935;
    --warning: #E65100;
    --warning-light: #FB8C00;
    --muted: #78909C;
    --bg: #F5F7FA;
    --bg-alt: #F8FAFE;
    --card-bg: #FFFFFF;
    --border: #E0E0E0;
    --border-strong: #BDBDBD;
    --text: #263238;
    --text-secondary: #546E7A;
    --rule: #E0E0E0;
    --radius: 8px;
    --radius-sm: 4px;
    --shadow: 0 2px 8px rgba(0,0,0,0.08);
    --shadow-hover: 0 4px 14px rgba(21,101,192,0.12);
    --font-serif: -apple-system, BlinkMacSystemFont, 'Segoe UI', 'PingFang SC', 'Microsoft YaHei', sans-serif;
    --font-sans: -apple-system, BlinkMacSystemFont, 'Segoe UI', 'PingFang SC', 'Microsoft YaHei', sans-serif;
    --font-mono: 'SF Mono', 'Cascadia Code', 'JetBrains Mono', Consolas, Menlo, monospace;
}
* { margin: 0; padding: 0; box-sizing: border-box; }
html { font-feature-settings: 'kern', 'liga', 'calt', 'tnum'; }
body { font-family: var(--font-sans); background: var(--bg); color: var(--text); line-height: 1.6; font-size: 14px; -webkit-font-smoothing: antialiased; }
.header { background: linear-gradient(135deg, var(--primary) 0%, var(--primary-dark) 100%); color: #FFFFFF; padding: 40px 0; margin-bottom: 30px; position: relative; box-shadow: 0 2px 12px rgba(13,71,161,0.18); }
.header-inner { max-width: 1400px; margin: 0 auto; padding: 0 30px; }
.header .eyebrow { font-family: var(--font-mono); font-size: 11px; letter-spacing: 0.18em; text-transform: uppercase; color: rgba(255,255,255,0.75); margin-bottom: 10px; font-weight: 600; }
.header h1 { font-size: 30px; font-weight: 600; margin-bottom: 8px; letter-spacing: -0.5px; line-height: 1.2; color: #FFFFFF; }
.header .subtitle { color: rgba(255,255,255,0.85); font-size: 14px; max-width: 720px; }
.header .meta { display: flex; gap: 28px; margin-top: 18px; flex-wrap: wrap; padding-top: 16px; border-top: 1px solid rgba(255,255,255,0.18); }
.header .meta-item { font-size: 13px; color: rgba(255,255,255,0.92); font-variant-numeric: tabular-nums; }
.header .meta-item strong { color: #FFFFFF; font-weight: 600; }
.cmdline-details { display: inline-block; vertical-align: middle; }
.cmdline-details summary { cursor: pointer; color: rgba(255,255,255,0.92); font-weight: 600; list-style: none; }
.cmdline-details summary::-webkit-details-marker { display: none; }
.cmdline-details summary strong { color: #FFFFFF; }
.cmdline-pre { white-space: pre-wrap; word-break: break-all; font-family: var(--font-mono); font-size: 11px; line-height: 1.5;
    color: rgba(255,255,255,0.92); margin: 8px 0 0; max-width: 900px; max-height: 160px; overflow-y: auto;
    background: rgba(255,255,255,0.12); padding: 8px 10px; border-radius: var(--radius-sm); }
.container { max-width: 1400px; margin: 0 auto; padding: 0 30px 60px; }
.summary-bar { display: grid; grid-template-columns: repeat(auto-fit, minmax(160px, 1fr)); gap: 16px; margin-bottom: 28px; }
.summary-card { background: var(--card-bg); border-radius: var(--radius); padding: 22px 20px; text-align: center; box-shadow: var(--shadow); border-top: 4px solid var(--muted); transition: transform 0.18s ease, box-shadow 0.18s ease; }
.summary-card:hover { transform: translateY(-2px); box-shadow: var(--shadow-hover); }
.summary-card.card-pass { border-top-color: var(--success); }
.summary-card.card-fail { border-top-color: var(--danger); }
.summary-card.card-crash { border-top-color: var(--warning); }
.summary-card .num { font-size: 36px; font-weight: 700; line-height: 1.2; font-variant-numeric: tabular-nums; letter-spacing: -0.5px; color: var(--text); }
.summary-card .label { font-size: 12px; color: var(--text-secondary); text-transform: uppercase; letter-spacing: 0.5px; margin-top: 6px; font-weight: 600; }
.summary-card.card-pass .num { color: var(--success); }
.summary-card.card-fail .num { color: var(--danger); }
.summary-card.card-crash .num { color: var(--warning); }
.progress-bar { background: #E8EAF6; border-radius: 20px; height: 28px; margin: 18px 0 8px; overflow: hidden; position: relative; box-shadow: inset 0 1px 2px rgba(0,0,0,0.04); }
.progress-fill { height: 100%; border-radius: 20px; transition: width 0.6s ease; display:flex; align-items:center; justify-content:center; }
.progress-fill.good { background: linear-gradient(90deg, var(--success-light), #66BB6A); }
.progress-fill.warn { background: linear-gradient(90deg, var(--warning-light), #FFA726); }
.progress-fill.bad { background: linear-gradient(90deg, var(--danger-light), #EF5350); }
.progress-text { font-size: 13px; font-weight: 600; color: white; text-shadow: 0 1px 2px rgba(0,0,0,0.3); letter-spacing: 0.3px; }
.progress-meta { display: flex; justify-content: space-between; font-size: 12px; color: var(--text-secondary); margin-bottom: 28px; padding: 0 4px; font-variant-numeric: tabular-nums; }
.progress-meta .pct { color: var(--primary); font-weight: 600; font-size: 13px; }
.section { margin-bottom: 32px; }
.section h2 { font-size: 18px; font-weight: 600; color: var(--text); margin-bottom: 16px; padding-bottom: 10px; border-bottom: 2px solid var(--border); letter-spacing: -0.2px; position: relative; display: flex; align-items: center; }
.section h2::after { content: ''; position: absolute; left: 0; bottom: -2px; width: 56px; height: 2px; background: var(--primary); }
.section h2 .icon { color: var(--primary); margin-right: 8px; }
.icon { margin-right: 8px; }
.model-section { background: var(--card-bg); border-radius: var(--radius); box-shadow: var(--shadow); margin-bottom: 24px; overflow: hidden; transition: box-shadow 0.18s ease; }
.model-section:hover { box-shadow: var(--shadow-hover); }
.model-header { display: flex; justify-content: space-between; align-items: center; padding: 16px 20px; background: linear-gradient(180deg, #FAFAFA 0%, #F5F5F5 100%); border-bottom: 1px solid var(--border); }
.model-header h3 { font-size: 16px; color: var(--primary); font-weight: 600; letter-spacing: -0.2px; }
.model-stats { display: flex; gap: 12px; align-items: center; }
.stat-pass { font-size: 13px; color: var(--success); font-weight: 500; font-variant-numeric: tabular-nums; }
.stat-rate { font-size: 12px; background: var(--primary); color: white; padding: 3px 12px; border-radius: 12px; font-weight: 600; font-variant-numeric: tabular-nums; letter-spacing: 0.2px; }
.group-section { padding: 18px 20px; border-bottom: 1px solid #F0F0F0; }
.group-section:last-child { border-bottom: none; }
.group-title { font-size: 13px; font-weight: 600; color: var(--text-secondary); margin-bottom: 12px; letter-spacing: 0.2px; }
table { width: 100%; border-collapse: collapse; font-size: 13px; }
thead th { background: #F5F5F5; padding: 10px 12px; text-align: left; font-weight: 600; color: var(--text-secondary);
            text-transform: uppercase; font-size: 11px; letter-spacing: 0.4px; border-bottom: 2px solid var(--border); }
tbody td { padding: 10px 12px; border-bottom: 1px solid #F0F0F0; vertical-align: middle; font-variant-numeric: tabular-nums; }
tbody tr:hover { background: var(--bg-alt); }
tbody tr:last-child td { border-bottom: none; }
td.center, th.center { text-align: center; }
td.num, th.num { text-align: right; font-family: var(--font-mono); font-variant-numeric: tabular-nums; white-space: nowrap; }
code { background: #F5F5F5; padding: 2px 6px; border-radius: 3px; font-family: var(--font-mono); font-size: 12px; color: var(--text); }
.status-pass, .status-fail, .status-crash, .status-skip { display: inline-block; font-weight: 700; font-size: 11px; letter-spacing: 0.5px; padding: 3px 9px; min-width: 52px; text-align: center; border-radius: 10px; }
.status-pass { color: var(--success); background: rgba(46,125,50,0.10); }
.status-fail { color: var(--danger); background: rgba(198,40,40,0.10); }
.status-crash { color: var(--warning); background: rgba(230,81,0,0.10); }
.status-skip { color: var(--muted); background: rgba(120,144,156,0.12); }
.badge-ignorable { display: inline-block; margin-left: 6px; font-size: 10px; font-weight: 700; letter-spacing: 0.4px; padding: 2px 7px; border-radius: 8px; background: rgba(255,152,0,0.14); color: #E65100; border: 1px solid rgba(230,81,0,0.30); cursor: help; vertical-align: middle; }
.badge-capability { display: inline-block; margin-left: 6px; font-size: 10px; font-weight: 700; letter-spacing: 0.4px; padding: 2px 7px; border-radius: 8px; background: rgba(30,136,229,0.14); color: #1565C0; border: 1px solid rgba(21,101,192,0.30); cursor: help; vertical-align: middle; }
.badge-mnn-oom { display: inline-block; margin-left: 6px; font-size: 10px; font-weight: 700; letter-spacing: 0.4px; padding: 2px 7px; border-radius: 8px; background: rgba(198,40,40,0.14); color: var(--danger); border: 1px solid rgba(198,40,40,0.30); cursor: help; vertical-align: middle; }
.badge-mnn-cascade { display: inline-block; margin-left: 6px; font-size: 10px; font-weight: 700; letter-spacing: 0.4px; padding: 2px 7px; border-radius: 8px; background: rgba(120,144,156,0.16); color: #37474F; border: 1px solid rgba(84,110,122,0.30); cursor: help; vertical-align: middle; }
.card-ignored { border-top: 3px solid #FB8C00; }
.card-ignored .num { color: #E65100; }
.card-capability { border-top: 3px solid var(--warning); }
.card-capability .num { color: var(--warning); }
.latency-warn { color: #F57C00; font-weight: 600; }
.latency-slow { color: var(--danger); font-weight: 700; }
.cv-stable { color: var(--success); font-size: 11px; font-weight: 600; }
.cv-moderate { color: #F57C00; font-size: 11px; font-weight: 600; }
.cv-unstable { color: var(--danger); font-size: 11px; font-weight: 700; }
.pivot-table { margin: 0; }
.resp-cell { max-width: 360px; min-width: 240px; font-size: 12px; vertical-align: middle; padding: 10px 12px !important; }
.resp-ok { display: inline-block; color: var(--success); font-weight: 600; font-size: 12px; letter-spacing: 0.2px; }
.resp-error { color: var(--danger); font-size: 11px; word-break: break-all; font-family: var(--font-mono); line-height: 1.45; }
.resp-detail { color: var(--text-secondary); font-size: 11px; line-height: 1.45; }
.resp-value { font-size: 12px; color: var(--text); font-variant-numeric: tabular-nums; }
.resp-value strong { color: var(--primary); font-weight: 700; }
.resp-models { font-weight: 600; color: var(--primary); display: block; margin-bottom: 4px; }
.resp-status { color: var(--text); }
.resp-empty { color: var(--muted); font-style: italic; }
.resp-json { font-size: 11px; line-height: 1.6; color: var(--text-secondary); font-family: var(--font-mono); }
.resp-json strong { color: var(--text); font-weight: 600; }
.resp-list { font-size: 11px; margin-top: 4px; color: var(--text-secondary); line-height: 1.5; }
.resp-link { display: inline-block; margin-left: 6px; font-size: 11px; color: var(--primary); text-decoration: none; font-weight: 600; padding: 2px 9px; border-radius: 10px; background: rgba(21,101,192,0.08); transition: background 0.15s, color 0.15s; }
.resp-link:hover { background: var(--primary); color: #FFFFFF; }
.resp-round { margin-bottom: 8px; padding-bottom: 8px; border-bottom: 1px dashed var(--border); font-size: 12px; }
.resp-round:last-child { border-bottom: none; margin-bottom: 0; padding-bottom: 0; }
.resp-kv { display: grid; grid-template-columns: max-content 1fr; gap: 4px 14px; font-family: var(--font-mono); font-size: 11px; line-height: 1.5; align-items: baseline; }
.resp-kv .kv-key { color: var(--text-secondary); font-weight: 600; white-space: nowrap; }
.resp-kv .kv-val { color: var(--text); font-variant-numeric: tabular-nums; word-break: break-all; }
.resp-kv .kv-more { grid-column: 1 / -1; color: var(--muted); font-size: 10px; margin-top: 4px; font-style: italic; }
.compare-table { background: var(--card-bg); border-radius: var(--radius); box-shadow: var(--shadow); overflow: hidden; }
.perf-round-grid { display: grid; grid-template-columns: repeat(auto-fill, minmax(230px, 1fr)); gap: 16px; margin-top: 4px; }
.perf-round-card { background: var(--card-bg); border-radius: var(--radius); box-shadow: var(--shadow); padding: 16px 18px; border-top: 3px solid var(--primary-light); transition: transform 0.18s ease, box-shadow 0.18s ease; }
.perf-round-card:hover { transform: translateY(-2px); box-shadow: var(--shadow-hover); }
.perf-round-card .perf-round-title { font-size: 13px; font-weight: 700; color: var(--primary); margin-bottom: 10px; letter-spacing: 0.2px; }
.perf-round-card .perf-metric { display: flex; justify-content: space-between; align-items: baseline; padding: 5px 0; font-size: 12px; border-bottom: 1px dashed #EEEEEE; }
.perf-round-card .perf-metric:last-child { border-bottom: none; }
.perf-round-card .perf-metric-label { color: var(--text-secondary); }
.perf-round-card .perf-metric-value { font-family: var(--font-mono); font-weight: 600; color: var(--text); font-variant-numeric: tabular-nums; white-space: nowrap; margin-left: 10px; }
.mode-tag { padding: 2px 9px; border-radius: 10px; font-size: 11px; font-weight: 600; letter-spacing: 0.2px; }
.mode-stream { background: #E3F2FD; color: var(--primary); }
.mode-nonstream { background: #FFF3E0; color: var(--warning); }
.mode-format-string { background: #ECEFF1; color: var(--text-secondary); }
.mode-format-array { background: #E1F5FE; color: #0277BD; }
.mode-format-object { background: #F3E5F5; color: #6A1B9A; }
.delta-up { color: var(--danger); font-weight: 600; font-family: var(--font-mono); }
.delta-down { color: var(--success); font-weight: 600; font-family: var(--font-mono); }
.crash-table { background: var(--card-bg); border-radius: var(--radius); box-shadow: var(--shadow); overflow: hidden; border-left: 4px solid var(--danger); }
.crash-table tbody td { color: var(--danger); }
.perf-summary { display: grid; grid-template-columns: repeat(auto-fit, minmax(170px, 1fr)); gap: 16px; margin-bottom: 22px; }
.perf-stat { background: var(--card-bg); border-radius: var(--radius); padding: 18px; text-align: center; box-shadow: var(--shadow); border-top: 3px solid var(--primary-light); }
.perf-value { display: block; font-size: 28px; font-weight: 700; color: var(--primary); font-variant-numeric: tabular-nums; letter-spacing: -0.5px; line-height: 1.1; }
.perf-label { font-size: 12px; color: var(--text-secondary); margin-top: 6px; text-transform: uppercase; letter-spacing: 0.4px; font-weight: 600; }
.chart-container { display: grid; grid-template-columns: 1fr 1fr; gap: 20px; }
.chart-container canvas { background: var(--card-bg); border-radius: var(--radius); padding: 16px; box-shadow: var(--shadow); height: 280px !important; }
.empty-state { background: var(--card-bg); border-radius: var(--radius); padding: 30px; text-align: center; color: var(--text-secondary); font-style: italic; font-size: 14px; box-shadow: var(--shadow); }
.footer { text-align: center; padding: 30px; color: var(--text-secondary); font-size: 12px; border-top: 1px solid var(--border); margin-top: 40px; letter-spacing: 0.2px; }
.model-link-card { background: var(--card-bg); border-radius: var(--radius); box-shadow: var(--shadow); padding: 18px 22px; margin-bottom: 12px; display: flex; justify-content: space-between; align-items: center; transition: transform 0.18s ease, box-shadow 0.18s ease; border-left: 3px solid var(--primary); }
.model-link-card:hover { transform: translateX(2px); box-shadow: var(--shadow-hover); }
.model-link-card a { text-decoration: none; color: var(--primary); font-weight: 600; font-size: 16px; letter-spacing: -0.2px; }
.model-link-card a:hover { color: var(--primary-dark); }
.model-link-card .model-link-stats { display: flex; gap: 18px; font-size: 12px; color: var(--text-secondary); font-variant-numeric: tabular-nums; letter-spacing: 0.2px; align-items: center; }
.startup-banner { background: linear-gradient(135deg, #FFEBEE 0%, #FFCDD2 100%); border: 1px solid var(--danger); border-left: 6px solid var(--danger); border-radius: var(--radius); padding: 22px 26px; margin-bottom: 24px; box-shadow: 0 3px 14px rgba(198,40,40,0.18); }
.startup-banner-title { font-size: 18px; font-weight: 700; color: var(--danger); margin-bottom: 8px; letter-spacing: -0.2px; }
.startup-banner-desc { font-size: 13px; color: #5D2020; line-height: 1.65; margin-bottom: 14px; }
.startup-banner-desc code { background: rgba(198,40,40,0.10); color: var(--danger); padding: 2px 6px; border-radius: 3px; font-size: 12px; }
.startup-table { width: 100%; border-collapse: collapse; background: rgba(255,255,255,0.7); border-radius: var(--radius-sm); overflow: hidden; }
.startup-table thead th { background: rgba(198,40,40,0.10); color: var(--danger); padding: 9px 12px; text-align: left; font-size: 11px; font-weight: 700; letter-spacing: 0.5px; text-transform: uppercase; border-bottom: 1px solid rgba(198,40,40,0.20); }
.startup-table tbody td { padding: 10px 12px; border-bottom: 1px solid rgba(198,40,40,0.10); vertical-align: top; font-size: 12px; color: #3E1212; }
.startup-table tbody tr:last-child td { border-bottom: none; }
.startup-detail { white-space: pre-wrap; word-break: break-word; font-family: var(--font-mono); font-size: 11px; line-height: 1.5; color: #4A1818; margin: 0; max-height: 240px; overflow-y: auto; background: rgba(255,255,255,0.6); padding: 8px 10px; border-radius: 3px; }
@media (max-width: 768px) {
    .chart-container { grid-template-columns: 1fr; }
    .header .meta { flex-direction: column; gap: 8px; }
    .pivot-table { font-size: 11px; }
}
@media print {
    .header { background: #333 !important; -webkit-print-color-adjust: exact; print-color-adjust: exact; }
    .summary-card, .model-section, table { box-shadow: none; border: 1px solid #ddd; }
}"""

    @staticmethod
    def _format_response_data(r):
        """格式化响应数据为 HTML 展示"""
        ep = r.name

        # chat/completions 特殊处理：即使 response_data 为空，只要有 text_response 就生成链接
        if "chat/completions" in ep:
            fmt_badge = _content_format_badge_html(r)
            if not r.passed:
                return f'<span class="resp-detail">{_html_escape(r.detail[:200])}</span>{fmt_badge}'
            mode = "stream" if r.is_stream else "nonstream"
            anchor = f"{r.model_name}_R{r.round_num}_{mode}"
            if r.is_stream:
                return f'<span class="resp-value">TTFT={r.ttft_ms:.0f}ms, {r.chunk_count} chunks</span>{fmt_badge} <a href="conversations.html#{anchor}" class="resp-link">查看详情 →</a>'
            else:
                resp_len = len(r.text_response) if r.text_response else 0
                return f'<span class="resp-value">响应长度: {resp_len} 字符</span>{fmt_badge} <a href="conversations.html#{anchor}" class="resp-link">查看详情 →</a>'

        if not r.response_data:
            if r.status_code == 200 and r.passed:
                return '<span class="resp-ok">OK</span>'
            elif r.detail:
                return f'<span class="resp-detail">{_html_escape(r.detail[:80])}</span>'
            return '-'

        data = r.response_data

        # 根据不同接口类型格式化展示
        if "models" in ep.lower() and "models" in data:
            # 与模型数量无关，统一显示 OK
            return '<span class="resp-ok">OK</span>'

        elif ep == "GET /status":
            loading = data.get("loading")
            error = data.get("error")
            if error:
                return f'<span class="resp-error">{_html_escape(str(error)[:80])}</span>'
            return f'<span class="resp-status">loading: {loading}</span>'

        elif ep == "GET /profile":
            # 排除以下 6 项指标——它们已在“性能报告”小节中独立展示，避免重复
            _PERF_KEYS_HIDDEN = {
                "time_to_first_token", "token_generation_time",
                "prompt_processing_rate", "token_generation_rate",
                "num_prompt_tokens", "num_generated_tokens",
            }
            keys = [k for k in data.keys() if k not in _PERF_KEYS_HIDDEN]
            if not keys:
                # 全部字段都是性能指标——下方“性能报告”已经展示，这里直接给 OK
                return '<span class="resp-ok">OK</span>'
            items = []
            for k in keys[:6]:
                v = data[k]
                if isinstance(v, (dict, list)):
                    v_str = f"[{len(v)} items]" if isinstance(v, list) else f"{{{len(v)} keys}}"
                else:
                    v_str = str(v)[:30]
                items.append(f'<span class="kv-key">{_html_escape(k)}</span><span class="kv-val">{_html_escape(v_str)}</span>')
            more = f'<div class="kv-more">+{len(keys)-6} more</div>' if len(keys) > 6 else ""
            return f'<div class="resp-kv">{"".join(items)}{more}</div>'

        elif ep == "POST /contextsize":
            ctx = data.get("contextsize", 0)
            return f'<span class="resp-value">contextsize = <strong>{ctx}</strong></span>'

        elif "textsplitter" in ep:
            seg_count = data.get("segment_count", 0)
            anchor = f"{r.model_name}_R{r.round_num}_textsplitter"
            return f'<span class="resp-value">{seg_count} segments</span> <a href="conversations.html#{anchor}" class="resp-link">查看详情 →</a>'

        elif ep == "POST /fetch":
            count = data.get("history_count", 0)
            if count == 0:
                return '<span class="resp-value">history: 空</span>'
            anchor = f"{r.model_name}_R{r.round_num}_fetch"
            return f'<span class="resp-value">{count} 条记录</span> <a href="conversations.html#{anchor}" class="resp-link">查看详情 →</a>'

        elif ep == "POST /reload":
            error = data.get("error", "")
            if error:
                return f'<span class="resp-error">{_html_escape(str(error)[:80])}</span>'
            return '<span class="resp-ok">OK</span>'

        else:
            if isinstance(data, dict) and data:
                items = [f'{_html_escape(k)}: {_html_escape(str(v)[:30])}' for k, v in list(data.items())[:3]]
                return f'<div class="resp-json">{"<br>".join(items)}</div>'
            return '<span class="resp-ok">OK</span>'

    @staticmethod
    def _build_pivot_table(results_subset, endpoint_list, rounds):
        """构建透视表：端点为行，R1/R2/R3 为列，最后一列显示响应数据"""
        endpoints_in_data = []
        for ep in endpoint_list:
            if any(r.name == ep for r in results_subset):
                endpoints_in_data.append(ep)

        if not endpoints_in_data:
            return ""

        round_headers = ""
        for rnd in rounds:
            round_headers += f'<th class="center">R{rnd}</th><th class="num">延迟</th>'

        html = f"""<table class="pivot-table">
        <thead><tr><th>端点</th>{round_headers}<th>响应数据</th></tr></thead>
        <tbody>"""

        # Endpoints whose response data should be shown per-round (large data with links)
        _per_round_endpoints = set(ReportGenerator.MODEL_PERF_ENDPOINTS) | {
            "POST /fetch", "POST /textsplitter", "POST /v1/textsplitter",
        }
        # /profile 是性能接口但返回体紧凑,不需要每轮都展开
        _per_round_endpoints.discard("GET /profile")

        for ep in endpoints_in_data:
            ep_results = {r.round_num: r for r in results_subset if r.name == ep}
            html += f'<tr><td><code>{_html_escape(ep)}</code></td>'

            all_round_results = []
            for rnd in rounds:
                r = ep_results.get(rnd)
                if r is None:
                    html += '<td class="center">-</td><td class="center">-</td>'
                else:
                    if r.skipped:
                        cls, txt = "status-skip", "SKIP"
                    elif r.crashed:
                        cls, txt = "status-crash", "CRASH"
                    elif r.passed:
                        cls, txt = "status-pass", "PASS"
                    else:
                        cls, txt = "status-fail", "FAIL"
                    lat_cls = ""
                    if r.latency_ms > 10000:
                        lat_cls = "latency-slow"
                    elif r.latency_ms > 3000:
                        lat_cls = "latency-warn"
                    # 已知缺陷标记: FAIL 但 ignorable=True 时,在徽章右侧加一个橙色"可忽略"小徽章,
                    # title 属性显示具体原因。这样表格里一眼能区分"真实回归"和"已知占位失败"。
                    # ignore_reason=="mnn_oom_cascade" 是一个独立的诊断标识(见 _classify_process_down)：
                    # 表示"疑似因同进程内 MNN 模型 OOM 拖垮进程而级联崩溃,需要人工排查根因"，
                    # 但崩溃永远是真实问题——该标识不再意味着 ignorable=True，只是用灰色的
                    # .badge-mnn-cascade 诊断徽章标注疑似关联，FAIL 状态和统计口径不受影响。
                    ignorable_badge = ""
                    if not r.passed:
                        ignore_reason = getattr(r, "ignore_reason", "")
                        if ignore_reason == "mnn_oom_cascade":
                            reason = _html_escape(getattr(r, "detail", "") or "疑似因同进程内 MNN 模型 OOM 拖垮进程而级联崩溃,需人工排查根因(已计入真实失败,非豁免)")
                            ignorable_badge = f'<span class="badge-mnn-cascade" title="{reason}">疑似级联崩溃(非豁免)</span>'
                        elif getattr(r, "ignorable", False):
                            reason = _html_escape(ignore_reason or "已知服务端缺陷")
                            ignorable_badge = f'<span class="badge-ignorable" title="{reason}">可忽略</span>'
                    # 模型能力局限标记: passed=True 但 model_capability_issue=True 时单列一个蓝色
                    # 徽章,与"可忽略"并列展示，避免与普通 PASS 混淆。统一判断 model_capability_issue
                    # 这一对通用字段(tool_calls 模型能力局限、服务端 [MODEL_DEFECT] 日志标记同样命中)。
                    if getattr(r, "model_capability_issue", False):
                        reason = _html_escape(getattr(r, "model_capability_reason", "") or "模型能力局限")
                        ignorable_badge += f'<span class="badge-capability" title="{reason}">模型能力局限</span>'
                    html += f'<td class="center"><span class="{cls}">{txt}</span>{ignorable_badge}</td>'
                    html += f'<td class="num {lat_cls}">{r.latency_ms:.0f} ms</td>'
                    all_round_results.append(r)

            # 响应数据列：对于有大量数据的端点，每轮都显示链接；其他端点只显示最后一轮
            if all_round_results:
                if ep in _per_round_endpoints:
                    resp_parts = []
                    for r in all_round_results:
                        resp_parts.append(f'<div class="resp-round">R{r.round_num}: {ReportGenerator._format_response_data(r)}</div>')
                    html += f'<td class="resp-cell">{"".join(resp_parts)}</td>'
                else:
                    resp_html = ReportGenerator._format_response_data(all_round_results[-1])
                    html += f'<td class="resp-cell">{resp_html}</td>'
            else:
                html += '<td class="resp-cell">-</td>'
            html += '</tr>'

        html += "</tbody></table>"
        return html

    @staticmethod
    def _case_status_badge_html(r):
        """根据 TestResult 的 skipped/crashed/passed/ignorable/ignore_reason/model_capability_issue
        计算状态徽章 HTML,与 _build_pivot_table 保持完全一致的判定与视觉语言,供不适合"端点 x 轮次"
        矩阵布局的逐用例明细表(Builder 集成代理/SampleApp)复用。返回 (cls, txt, extra_badges_html)。"""
        if r.skipped:
            cls, txt = "status-skip", "SKIP"
        elif r.crashed:
            cls, txt = "status-crash", "CRASH"
        elif r.passed:
            cls, txt = "status-pass", "PASS"
        else:
            cls, txt = "status-fail", "FAIL"
        extra_badges = ""
        if not r.passed:
            ignore_reason = getattr(r, "ignore_reason", "")
            if ignore_reason == "mnn_oom_cascade":
                reason = _html_escape(getattr(r, "detail", "") or "疑似因同进程内 MNN 模型 OOM 拖垮进程而级联崩溃,需人工排查根因(已计入真实失败,非豁免)")
                extra_badges = f'<span class="badge-mnn-cascade" title="{reason}">疑似级联崩溃(非豁免)</span>'
            elif getattr(r, "ignorable", False):
                reason = _html_escape(ignore_reason or "已知服务端缺陷")
                extra_badges = f'<span class="badge-ignorable" title="{reason}">可忽略</span>'
        # 统一判断 model_capability_issue,与 _build_pivot_table 保持同一套口径。
        if getattr(r, "model_capability_issue", False):
            reason = _html_escape(getattr(r, "model_capability_reason", "") or "模型能力局限")
            extra_badges += f'<span class="badge-capability" title="{reason}">模型能力局限</span>'
        return cls, txt, extra_badges

    @staticmethod
    def _build_case_detail_table(results, show_model_column=True):
        """构建逐用例明细表：不同于 _build_pivot_table 的"端点 x 轮次"矩阵布局(那种布局假定
        同一端点会跨多轮重复出现),Builder 集成代理 / SampleApp / tool_calls 协议测试这类用例
        通常每个模型/后端只跑一次,按用例名逐行展示 通过状态/模型或后端/耗时/详情/模型能力问题
        更直观。复用既有 .pivot-table/.status-*/.badge-* 类名体系，保持一致的视觉语言。"""
        if not results:
            return ""
        model_header = "<th>模型/后端</th>" if show_model_column else ""
        html = f"""<table class="pivot-table">
        <thead><tr><th>用例</th>{model_header}<th class="center">状态</th><th class="num">耗时</th><th>详情</th><th>模型能力问题</th></tr></thead>
        <tbody>"""
        for r in results:
            cls, txt, extra_badges = ReportGenerator._case_status_badge_html(r)
            model_cell = f'<td>{_html_escape(r.model_name)}</td>' if show_model_column else ""
            capability_cell = ""
            if getattr(r, "model_capability_issue", False):
                reason = _html_escape(getattr(r, "model_capability_reason", "") or "模型能力局限")
                capability_cell = f'<span class="badge-capability" title="{reason}">模型能力局限</span>'
            html += f"""<tr><td><code>{_html_escape(r.name)}</code></td>{model_cell}
            <td class="center"><span class="{cls}">{txt}</span>{extra_badges}</td>
            <td class="num">{r.latency_ms:.0f} ms</td>
            <td>{_html_escape(r.detail)}</td>
            <td class="center">{capability_cell}</td></tr>"""
        html += "</tbody></table>"
        return html

    @staticmethod
    def _cmdline_meta_html(cmdline):
        """构建 header 区域"命令行"展示项：展示本次运行调用 test_service.py 时的完整命令行，
        复用 --font-mono 等宽字体样式（.cmdline-pre，与 .startup-detail 同一套设计语言，
        仅针对深色 header 背景调整了配色），超长命令行通过 <details> 折叠，避免撑爆 header 布局。
        未提供 cmdline（例如向后兼容旧调用点）时不渲染该项。"""
        if not cmdline:
            return ""
        # 默认展开（open 属性）：其它 meta-item 都是标签+值直接可见，命令行若默认折叠，
        # 用户不点击就只看到"命令行"这个词、看不到任何内容，容易误以为该字段是空的。
        return (f'<span class="meta-item"><details class="cmdline-details" open><summary><strong>命令行</strong></summary>'
                f'<pre class="cmdline-pre">{_html_escape(cmdline)}</pre></details></span>')

    # --suite 取值 → 该 suite 本轮会覆盖到的测试完备性矩阵列（类别名）。
    # full 现在也真正执行 SampleApp(见 _run_full_suite 阶段6),覆盖全部类别;
    # 未被本轮 suite 覆盖的类别在矩阵中统一显示"未运行本轮",避免与真实失败混淆。
    _SUITE_MATRIX_COVERAGE = {
        "full": {"通用接口", "文本chat", "多模态", "多模型路由", "GGUF显式加载", "SampleApp", "Builder/OpenClaw"},
        "model": {"通用接口", "文本chat", "多模态"},
        "multimodal": {"多模态"},
        "multi_model": {"多模型路由"},
        "gguf": {"GGUF显式加载"},
        "sampleapp": {"SampleApp"},
        "mnn": {"通用接口", "文本chat"},
        "qnn": {"通用接口", "文本chat", "多模态"},
        "prompt_fidelity": {"提示词保真"},
    }
    MATRIX_CATEGORIES = ("通用接口", "文本chat", "多模态", "多模型路由", "GGUF显式加载", "SampleApp", "Builder/OpenClaw", "提示词保真")

    # 设备后缀形式如 " (CPU)"/" (GPU)"/" (NPU)"：GGUF 模型未在 config.json 显式指定 device 时
    # 由服务自行决定实际加载设备(见 _run_model_suite),报告把这类模型的展示名统一打上该后缀,
    # 使常规生命周期测试(阶段2)与显式设备加载回归(阶段4)落在同一行,不再拆成 3 行。
    _DEVICE_SUFFIX_RE = re.compile(r" \([A-Z]+\)$")

    @staticmethod
    def _strip_device_suffix(name):
        """去掉展示名上的设备后缀,还原成服务内部注册的裸模型名。多模型并发阶段(阶段3)
        产生的 TestResult.name 里引用的仍是裸模型名,需要用这个还原后的名字做子串匹配,
        否则 GGUF 模型被打上设备后缀后,"多模型路由"这一列会因为字符串不再匹配而漏判。"""
        return ReportGenerator._DEVICE_SUFFIX_RE.sub("", name)

    @staticmethod
    def _env_constraint_reason(r):
        """判断某条未通过的 TestResult 是否属于"环境受限"的真实失败(而非未预期的回归),
        用于测试完备性矩阵的展示层面归类为"跳过(注明原因)"。仅影响矩阵单元格的展示状态,
        不修改 TestResult 本身的 passed/crashed/ignorable/skipped 字段——这些失败仍然如实
        计入 failed/crashed 统计和退出码判定(崩溃/资源不足永远是需要关注的真实问题,这里
        只是让矩阵里的"失败"状态更聚焦于真正未预期的回归,不与已知的资源限制混在一起)。"""
        detail = r.detail or ""
        detail_lower = detail.lower()
        if "insufficient_memory" in detail_lower or "内存不足" in detail:
            return "内存不足(insufficient_memory)"
        if getattr(r, "ignore_reason", "") == "mnn_oom_cascade":
            return "疑似MNN OOM级联崩溃(需人工排查,已计入失败统计)"
        return None

    @staticmethod
    def _matrix_cell_status(matched_results):
        """把某个模型×类别对应的一批 TestResult 归纳为矩阵单元格状态,返回 (status, reason)。
        reason 仅在 status=="跳过" 且能定位到具体原因时非空,用于单元格 title 提示。"""
        if not matched_results:
            return "未运行本轮", ""
        if all(r.skipped for r in matched_results):
            reasons = sorted({r.detail for r in matched_results if r.detail})
            return "跳过", "; ".join(reasons[:3])
        if all(r.passed or getattr(r, "ignorable", False) for r in matched_results):
            return "通过", ""
        # 未通过的结果里，如果全部都能归因到已知的"环境受限"信号(MNN 内存不足优雅拒绝、
        # 疑似 MNN OOM 级联崩溃等)，或本身已被测试逻辑正确判定为 skipped(如模型能力局限
        # 的 tool_calls 探测)，矩阵展示层面视为"跳过(注明原因)"，不改变底层统计口径。这里
        # 必须把 r.skipped 一起从 failing 里排除，否则同一类别下"部分通过 + 部分合理跳过"的
        # 混合结果会因为不满足"全部 skipped"也不满足"全部 passed/ignorable"而误落入失败分支。
        failing = [r for r in matched_results if not (r.passed or getattr(r, "ignorable", False) or r.skipped)]
        if not failing:
            skip_reasons = sorted({r.detail for r in matched_results if r.skipped and r.detail})
            return "跳过", "; ".join(skip_reasons[:3])
        env_reasons = [ReportGenerator._env_constraint_reason(r) for r in failing]
        if all(env_reasons):
            return "跳过", "; ".join(sorted(set(env_reasons))[:3])
        return "失败", ""

    # "通用接口"是兜底类别，只应容纳"没有专属矩阵列"的模型级用例。tool_calls/GGUF显式
    # 加载/Builder/SampleApp 都已经有各自的专属列（见下方各分支）、以及独立的报告展示区块
    # (report_tool_calls.html、逐模型报告的同名区块等)，其判定结果(尤其是 skipped=True 这
    # 类模型能力局限/环境限制)与"通用接口"本意（GET /、/contextsize、/textsplitter 等真正
    # 与模型能力无关的端点）毫无关系；一旦遗漏排除，就会被重复计入"通用接口"这一列，让它的
    # 判定结果被其它专属列的原因污染（真实案例：tool_calls 机会性探测的 skipped 曾污染
    # phi4-v81/qwen2.5vl3b-8480 的"通用接口"列，详见 4.9）。新增任何专属矩阵列时，必须把该
    # 列的匹配条件同步加入这里，防止同一条结果被"通用接口"重复计入。
    @staticmethod
    def _has_dedicated_matrix_category(name):
        return (name.startswith("POST /v1/chat/completions (tool_call")
                or name.startswith("SAMPLEAPP:")
                or name.startswith("BUILDER")
                or name.startswith("PROMPT_FIDELITY:")
                or "explicit_load" in name)

    @staticmethod
    def _build_completeness_matrix(all_results, model_names, suite_name):
        """测试完备性矩阵：行为模型,列为测试类别,展示各模型在各类别下本轮的通过/失败/跳过/未运行本轮状态。"""
        if not model_names:
            return ""
        covered = ReportGenerator._SUITE_MATRIX_COVERAGE.get(suite_name, set())
        perf_endpoints = set(ReportGenerator.MODEL_PERF_ENDPOINTS)

        rows_html = ""
        for m in model_names:
            base_m = ReportGenerator._strip_device_suffix(m)
            rows_html += f"<tr><td>{_html_escape(m)}</td>"
            for cat in ReportGenerator.MATRIX_CATEGORIES:
                reason = ""
                if cat not in covered:
                    status = "未运行本轮"
                else:
                    if cat == "通用接口":
                        matched = [r for r in all_results if r.model_name == m
                                   and r.name not in perf_endpoints and "multimodal" not in r.name
                                   and not ReportGenerator._has_dedicated_matrix_category(r.name)]
                    elif cat == "文本chat":
                        matched = [r for r in all_results if r.model_name == m
                                   and r.name in perf_endpoints and "multimodal" not in r.name]
                    elif cat == "多模态":
                        matched = [r for r in all_results if r.model_name == m and "multimodal" in r.name]
                    elif cat == "多模型路由":
                        matched = [r for r in all_results if r.model_name == "_multi_model_" and base_m in r.name]
                    elif cat == "GGUF显式加载":
                        matched = [r for r in all_results if r.model_name.startswith(m) and "explicit_load" in r.name]
                    elif cat == "Builder/OpenClaw":
                        matched = [r for r in all_results if r.model_name == m and r.name.startswith("BUILDER")]
                    elif cat == "提示词保真":
                        matched = [r for r in all_results if r.model_name == m and r.name.startswith("PROMPT_FIDELITY:")]
                    else:  # SampleApp
                        matched = [r for r in all_results if r.model_name == m and r.name.startswith("SAMPLEAPP:")]
                    status, reason = ReportGenerator._matrix_cell_status(matched)
                cls = {"通过": "status-pass", "失败": "status-fail"}.get(status, "status-skip")
                title_attr = f' title="{_html_escape(reason)}"' if reason else ""
                rows_html += f'<td class="center"{title_attr}><span class="{cls}">{status}</span></td>'
            rows_html += "</tr>"

        header_html = "".join(f"<th>{_html_escape(cat)}</th>" for cat in ReportGenerator.MATRIX_CATEGORIES)
        return f"""<div class="section"><h2><span class="icon">&#128203;</span> 测试完备性矩阵</h2>
        <table class="pivot-table"><thead><tr><th>模型</th>{header_html}</tr></thead><tbody>
        {rows_html}
        </tbody></table></div>"""

    @staticmethod
    def _generate_multi_backend_detail_html(multi_model_results, loaded_entries, out_dir, remote_mode=False, cmdline=""):
        """生成"多类型同时加载"的完整详情页(report_multi_backend_coexistence.html)。

        承载主报告不适合展示的高密度内容——逐项检查记录(每条检查的完整原始 detail 文本，
        如 insufficient_memory 的字节数明细)、后端共存矩阵每个组合的完整原因说明。主报告
        (generate_summary_html)只保留极简摘要 + 指向本页面的链接，与其它区块的密度保持
        一致。仅在存在多模型检查结果时才生成并返回 True，调用方据此决定是否渲染链接。
        """
        if not multi_model_results:
            return False

        # 按检查类别分组，而不是把全部检查项摊成一张不分类的长列表——同一类别的检查项
        # (尤其是逐模型重复出现的 "MULTI: chat route → <model>") 集中在同一张子表格里,
        # 复用既有 .group-section/.group-title 样式(与"通用接口测试"等区块保持一致)。
        _check_groups = {}
        for r in multi_model_results:
            if r.skipped:
                status_text, status_class = "SKIP", "skip"
            elif r.crashed:
                status_text, status_class = "CRASH", "crash"
            elif r.passed:
                status_text, status_class = "PASS", "pass"
            elif getattr(r, "ignorable", False):
                status_text, status_class = "IGN", "ignored"
            else:
                status_text, status_class = "FAIL", "fail"
            check_desc = ReportGenerator._describe_multi_check(r.name)
            category = ReportGenerator._categorize_multi_check(r.name)
            row_html = f"""<tr>
                <td><code>{_html_escape(r.name)}</code></td>
                <td class=\"resp-detail\">{_html_escape(check_desc)}</td>
                <td><span class=\"badge {status_class}\">{status_text}</span></td>
                <td class=\"center\">{r.status_code}</td>
                <td>{_html_escape(r.detail)}</td>
            </tr>"""
            _check_groups.setdefault(category, []).append(row_html)

        _category_order = [c[0] for c in ReportGenerator._MULTI_CHECK_CATEGORIES] + [ReportGenerator._MULTI_CHECK_CATEGORY_FALLBACK]
        _group_sections_html = ""
        for category in _category_order:
            rows = _check_groups.get(category)
            if not rows:
                continue
            _group_sections_html += f"""<div class=\"group-section\">
                <div class=\"group-title\">{_html_escape(category)}（{len(rows)}）</div>
                <table class=\"compare-table\"><thead><tr><th>检查项</th><th>说明</th><th>状态</th><th>HTTP</th><th>详情</th></tr></thead><tbody>{''.join(rows)}</tbody></table>
            </div>"""
        checks_html = (f'<div class="model-section">{_group_sections_html}</div>'
                        if _group_sections_html else '<div class="empty-state">未捕获到任何检查项</div>')

        loaded_rows = ""
        for entry in loaded_entries:
            loaded_rows += f"""<tr>
                <td>{_html_escape(entry.get('id', ''))}</td>
                <td><code>{_html_escape(entry.get('backend', ''))}</code></td>
                <td><code>{_html_escape(entry.get('device', ''))}</code></td>
                <td class=\"num\">{_html_escape(str(entry.get('context_length', '')))}</td>
            </tr>"""
        loaded_html = (f'<table class="compare-table"><thead><tr><th>模型</th><th>后端</th><th>设备</th><th>上下文</th></tr></thead><tbody>{loaded_rows}</tbody></table>'
                        if loaded_rows else '<div class="empty-state">未捕获到已加载模型的 backend/device 明细</div>')

        coexistence_html = '<div class="empty-state">本次未产生后端共存矩阵结果</div>'
        matrix_result = next(
            (r for r in multi_model_results
             if r.name == "MULTI: backend coexistence matrix (triple + pairwise fallback)"),
            None
        )
        if matrix_result and matrix_result.response_data and matrix_result.response_data.get("coexistence_matrix"):
            cm = matrix_result.response_data["coexistence_matrix"]
            _CM_STATUS_CLASS = {"pass": "status-pass", "fail": "status-fail",
                                 "skip": "status-skip", "unknown": "status-skip"}
            _CM_STATUS_TEXT = {"pass": "PASS", "fail": "FAIL", "skip": "SKIP", "unknown": "N/A"}
            _CM_PAIR_LABEL = {"npu+gpu": "QNN/NPU + GGUF/GPU", "npu+cpu": "QNN/NPU + MNN/CPU",
                               "gpu+cpu": "GGUF/GPU + MNN/CPU"}
            triple = cm["triple"]
            triple_badge = f'<span class="{_CM_STATUS_CLASS.get(triple["status"], "status-skip")}">{_CM_STATUS_TEXT.get(triple["status"], triple["status"].upper())}</span>'
            pair_rows = ""
            for pair_key, pair_info in cm["pairs"].items():
                p_status = pair_info["status"]
                p_badge = f'<span class="{_CM_STATUS_CLASS.get(p_status, "status-skip")}">{_CM_STATUS_TEXT.get(p_status, p_status.upper())}</span>'
                pair_rows += f"""<tr>
                    <td>{_html_escape(_CM_PAIR_LABEL.get(pair_key, pair_key))}</td>
                    <td class=\"center\">{p_badge}</td>
                    <td>{_html_escape(pair_info["detail"])}</td>
                </tr>"""
            coexistence_html = f"""<table class="compare-table"><thead><tr><th>组合</th><th class="center">状态</th><th>详情</th></tr></thead><tbody>
            <tr><td><strong>QNN/NPU + GGUF/GPU + MNN/CPU（三后端同时驻留）</strong></td><td class="center">{triple_badge}</td><td>{_html_escape(triple["detail"])}</td></tr>
            {pair_rows}
            </tbody></table>"""

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>多类型同时加载 - 详细记录</title>
<style>
{ReportGenerator._common_css()}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Multi-Backend Coexistence Detail</div>
        <h1>多类型同时加载 &middot; 详细记录</h1>
        <p class="subtitle">后端共存矩阵完整原因与逐项检查记录</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>模式:</strong> {"远程" if remote_mode else "本地"}</span>
            <span class="meta-item"><a href="report.html" style="color: var(--accent); text-decoration: none; border-bottom: 1px solid var(--accent); font-weight: 600;">← 返回总汇报</a></span>
            {ReportGenerator._cmdline_meta_html(cmdline)}
        </div>
    </div>
</div>

<div class="container">

<div class="section">
<h2><span class="icon">&#128187;</span> 已加载 backend/device</h2>
{loaded_html}
</div>

<div class="section">
<h2><span class="icon">&#129520;</span> 后端共存矩阵（三后端 + 两两降级，完整详情）</h2>
{coexistence_html}
</div>

<div class="section">
<h2><span class="icon">&#128203;</span> 逐项检查记录</h2>
<div class="resp-detail" style="margin: -4px 0 10px;">本节（多类型同时加载）全部检查项的完整原始记录，已按类别分组（单模型路由验证、后端共存与两两降级验证、通用接口与异常路由、并发与故障恢复），便于快速定位同类检查而不必翻阅一整张不分类的长列表。</div>
{checks_html}
</div>

<div class="footer">
    多类型同时加载详细记录 &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}
</div>

</div>
</body>
</html>"""

        ReportGenerator._assert_no_placeholder_leak(html, "多类型同时加载详情页 report_multi_backend_coexistence.html")
        out_path = Path(out_dir) / "report_multi_backend_coexistence.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] 多类型同时加载详情: {out_path}")
        return True

    # ------------------------------------------------------------------
    # skill_capacity 套件（技能装载前沿）报告
    # ------------------------------------------------------------------
    # 设计约束：这里**不硬编码任何前沿数值**，全部从本次运行的 TestResult.response_data
    # 里读（数据契约见 _run_skill_capacity_suite 里 `{arm}_frontier` 结果的 data 字段）。
    # 报告表述纪律（不得夸大也不得埋没）：
    #   * 只有 usable_for_gain_ratio=True（converged 且前沿点未预算饱和）的数字才允许
    #     以精确值/精确倍数呈现；
    #   * 未收敛或饱和一律渲染成「≥N 下界」并附机械原因，禁止四舍五入成看起来精确的倍数；
    #   * repeat 次数一并展示，且固定附「repeat=1 时不声称统计显著」的口径说明。
    # 历史作废数字（旧技能池 44/77/1.75x、tie_aware_l2=true 下的 111/2.5227）只在
    # 「追溯」小节以「已作废/已被取代」的措辞出现，永不进结论位置。
    _SC_ARM_LABEL = {
        "legacy": "改造前 legacy（全部新开关关闭）",
        "optimized": "改造后 optimized（出厂默认）",
    }

    _SC_DISCIPLINE_HTML = """<ul class="sc-note">
    <li><strong>可引用口径</strong>：容量池（目标技能分数严格最高、不存在同分 tie-break，且池组成跨 N 严格前缀稳定）+ 直连 GenieAPIService（<code>-n -1 -g -d 3</code>）+ 出厂默认 <code>skill_disclosure.tie_aware_l2=false</code>。</li>
    <li><strong>统计强度</strong>：本套件默认 <code>--skill_capacity_repeat</code> 次采样取多数票。<em>repeat=1 时未做重复性检验，只能表述为「效应量极大且方向明确」，不声称统计显著。</em></li>
    <li><strong>真伪三字段</strong>：只有同时满足 <code>Skills-Kept == Skills-Total</code>（一条技能都没被丢弃）、<code>skills_kept_at_budget_cap=False</code>（未咬预算上限）、<code>Tokens-Out</code> 随 N 单调递增，才能说<em>本次测量未观察到</em>「预算耗尽导致保留条数被钉死」这种旁路式假提升的迹象（这是「未观察到迹象」，不是因果层面的「已排除」）——历史上曾因 skills 预算被砍导致保留条数恒定、体量不随 N 增长，测出过一个假的高前沿值。</li>
    <li><strong>已作废、不得引用的数字</strong>：旧技能池的前沿 44 / 77 与 1.75x 倍数（旧池组成随 N 跳变，是构造产物而非容量差）；<code>tie_aware_l2=true</code> 下的 111 / 2.5227（已被该开关默认值翻转为 false 后的新测量取代，仅供追溯）。</li>
    <li><strong>不构成旧数字的复活</strong>：容量池 legacy 与旧池 legacy 撞到同一个前沿值是<em>机制同源的必然</em>——两池共用同一套技能 description/正文生成器，legacy 档全部按 L2 全量渲染时单条目录条目体量几乎相同，容量边界由「N × 单条体量」直接决定。禁止跨池互相引用。</li>
    <li><strong>环境性跳过如实标注</strong>：目标模型或其 <code>config.json</code>/<code>genie_config.json</code> 缺失时精确跳过并标注环境原因，不伪造数字（<code>qwen2.5_omini</code> 历史上即因两处目录缺 <code>config.json</code> 被跳过）。</li>
    </ul>"""

    _SC_TIE_PATHOLOGY_HTML = """<ul class="sc-note">
    <li><strong>结论（与容量数字独立，不参与倍数计算）</strong>：当多个候选技能相关性得分<em>完全相同</em>时，<strong>技能目录里的排列顺序单独决定模型去读哪一条</strong>。判别实验：固定技能数、分数、正文与全部开关，<em>仅</em>把目标技能改名使其在同分组内排到首位，目标被选中率由 <code>0.000</code> 变为 <code>1.000</code>。</li>
    <li>与之配套被严格证伪的三条竞争解释：「提前满足（未 read 就直接作答）」、「工具调用阈值过高（不敢调用工具）」、「池内位置偏置」——实测模型 <strong>100% 发起 read</strong>，只是读了排序在目标之前的同分干扰项。</li>
    <li><strong><code>skill_disclosure.tie_aware_l2</code> 默认值为 false 的实测依据</strong>：该开关会把整个同分组一起提升到 L2；在「整池同分」的守门用例（N=64）下显式置为 <code>true</code> 会直接触发 <code>HTTP 422 (local input overflow)</code>，而默认 <code>false</code> 时 <code>Skills-Kept == Skills-Total</code> 且提示词体量远低于上下文上限。该开关另已被其自身预设判据证伪（目标 5/5 次成功升到 L2 而选中率仍为 0.000），<em>保留为默认安全开关，不得作为瓶颈修复呈现</em>。</li>
    </ul>"""

    @staticmethod
    def _sc_collect_frontiers(all_results):
        """把 skill_capacity 的前沿结果聚合成 {model: {arm: entry}}。

        识别依据是 response_data 里有 frontier_skills 字段（而不是靠用例名做字符串
        猜测），这样即使日后新增档位/改名也不会静默漏掉。"""
        frontiers = {}
        for r in all_results:
            if not r.name.startswith("SKILL_CAPACITY:"):
                continue
            data = r.response_data or {}
            if "frontier_skills" not in data:
                continue
            model = data.get("model") or r.model_name
            arm = data.get("arm") or "unknown"
            curve = data.get("probe_curve") or []
            frontier = data.get("frontier_skills")
            point = next((e for e in reversed(curve) if e.get("n") == frontier), None)
            frontiers.setdefault(model, {})[arm] = {
                "frontier": frontier,
                "converged": bool(data.get("converged")),
                "saturated": bool(data.get("frontier_saturated")),
                "usable": bool(data.get("usable_for_gain_ratio")),
                "note": data.get("note") or "",
                "curve": curve,
                "point": point,
                "result": r,
            }
        return frontiers

    @staticmethod
    def _sc_frontier_text(entry):
        """单档前沿值的展示文本 + 机械原因。未收敛/饱和一律写成「≥N 下界」。"""
        if not entry:
            return "N/A", "本次未产生该档位的前沿搜索结果"
        n = entry["frontier"]
        if entry["usable"]:
            return str(n), ""
        reasons = []
        if not entry["converged"]:
            reasons.append("未收敛（倍增探测到 --skill_capacity_max 仍全部通过，真实前沿在上界之外）")
        if entry["saturated"]:
            reasons.append("前沿点预算饱和（Skills-Kept < Skills-Total，保留条数由预算而非 N 决定，与装载能力解耦）")
        return f"&ge; {n}（下界）", "；".join(reasons) or "usable_for_gain_ratio=False"

    @staticmethod
    def _sc_gain_text(legacy, optimized):
        """提升倍数：两档都 usable 才允许给精确倍数，否则只给下界或直接 N/A。"""
        if not legacy or not optimized:
            return "N/A", "缺少对照档位（需要 --skill_capacity_arms both）"
        lf, of = legacy["frontier"], optimized["frontier"]
        if not isinstance(lf, int) or not isinstance(of, int) or lf <= 0:
            return "N/A", f"legacy 前沿为 {lf}，无法作为倍数分母"
        ratio = of / lf
        if legacy["usable"] and optimized["usable"]:
            return f"{ratio:.4f}x", ""
        return (f"&ge; {ratio:.2f}x（下界）",
                "至少一档 usable_for_gain_ratio=False，按纪律只能给下界，不得呈现为精确倍数")

    @staticmethod
    def _sc_capability_rows(frontiers):
        """能力矩阵表体（主报告卡片与详情页共用同一份渲染，避免两处口径漂移）。"""
        rows = ""
        for model in sorted(frontiers):
            arms = frontiers[model]
            legacy, optimized = arms.get("legacy"), arms.get("optimized")
            legacy_text, legacy_note = ReportGenerator._sc_frontier_text(legacy)
            opt_text, opt_note = ReportGenerator._sc_frontier_text(optimized)
            gain_text, gain_note = ReportGenerator._sc_gain_text(legacy, optimized)
            ref = optimized or legacy
            point = (ref or {}).get("point") or {}
            tokens_out, ctx = point.get("tokens_out"), point.get("context_size")
            if isinstance(tokens_out, int) and isinstance(ctx, int) and ctx > 0:
                ctx_text = f"{tokens_out / ctx * 100:.1f}%<br><small>{tokens_out} / {ctx} tokens</small>"
            else:
                ctx_text = "N/A"
            kept, total = point.get("skills_kept"), point.get("skills_total")
            if isinstance(kept, int) and isinstance(total, int) and total > 0:
                keep_text = f"{kept / total * 100:.0f}%<br><small>{kept} / {total}</small>"
            else:
                keep_text = "N/A"
            trials = point.get("trials")
            repeat_text = f"repeat={trials}" if isinstance(trials, int) else "repeat=?"
            note_bits = [b for b in (
                (f"legacy: {legacy_note}" if legacy_note else ""),
                (f"optimized: {opt_note}" if opt_note else ""),
                (f"倍数: {gain_note}" if gain_note else ""),
            ) if b]
            note_html = (f'<div class="resp-detail" style="margin-top:4px;">{_html_escape("；".join(note_bits))}</div>'
                         if note_bits else "")
            rows += f"""<tr>
                <td><strong>{_html_escape(model)}</strong><div class="resp-detail">{_html_escape(repeat_text)}</div>{note_html}</td>
                <td class="center">{legacy_text}</td>
                <td class="center"><strong>{opt_text}</strong></td>
                <td class="center">{gain_text}</td>
                <td class="center">{keep_text}</td>
                <td class="center">{ctx_text}</td>
            </tr>"""
        return rows

    _SC_CAPABILITY_HEADER = ("<thead><tr><th>模型</th><th class=\"center\">改造前前沿<br><small>legacy</small></th>"
                             "<th class=\"center\">改造后前沿<br><small>optimized</small></th>"
                             "<th class=\"center\">提升倍数</th><th class=\"center\">技能保留率<br><small>前沿点 Kept/Total</small></th>"
                             "<th class=\"center\">上下文占用率<br><small>前沿点 Tokens-Out/Context</small></th></tr></thead>")

    @staticmethod
    def _sc_curve_table_html(entry):
        """单档二分搜索曲线：N × 判据 × 全部账本字段（含 422 与紧急截断）。"""
        rows = ""
        for e in entry["curve"]:
            err = e.get("error") or ""
            is_422 = "422" in err
            def _flag(v, good="是", bad="否"):
                if v is None:
                    return '<span class="status-skip">未知</span>'
                return (f'<span class="status-pass">{good}</span>' if v
                        else f'<span class="status-fail">{bad}</span>')
            verdict = ('<span class="badge pass">PASS</span>' if e.get("passed")
                       else ('<span class="badge ignored">PARTIAL</span>' if e.get("partial")
                             else '<span class="badge fail">FAIL</span>'))
            is_frontier = (e.get("n") == entry["frontier"])
            row_style = ' style="background: rgba(25,118,210,0.08);"' if is_frontier else ""
            kept, total = e.get("skills_kept"), e.get("skills_total")
            kept_text = f"{kept} / {total}"
            if isinstance(kept, int) and isinstance(total, int) and kept < total:
                kept_text += ' <span class="status-fail">(&lt;)</span>'
            tiers = "/".join("?" if e.get(k) is None else str(e.get(k))
                             for k in ("skills_l2", "skills_l1", "skills_l0"))
            tokens_out, ctx = e.get("tokens_out"), e.get("context_size")
            occupancy = (f"{tokens_out} / {ctx}" if tokens_out is not None and ctx is not None else "N/A")
            rows += f"""<tr{row_style}>
                <td class="num"><strong>{e.get('n')}</strong>{' &#9733;' if is_frontier else ''}</td>
                <td class="center">{verdict}</td>
                <td class="center">{_flag(e.get('answered'))}</td>
                <td class="center">{_flag(e.get('picked'))}</td>
                <td class="center">{_flag(e.get('target_in_prompt'))}</td>
                <td class="center"><code>{_html_escape(str(e.get('target_form') or '-'))}</code></td>
                <td class="center">{kept_text}</td>
                <td class="center">{_html_escape(tiers)}</td>
                <td class="center">{_html_escape(str(e.get('skills_budget_tokens')))}</td>
                <td class="center">{_html_escape(occupancy)}</td>
                <td class="center">{_flag(e.get('emergency_truncated'), good='是', bad='否')}</td>
                <td class="center">{'<span class="status-fail">422</span>' if is_422 else '-'}</td>
                <td class="resp-detail">{_html_escape(err[:200])}</td>
            </tr>"""
        head = ("<thead><tr><th>N</th><th class=\"center\">判定</th><th class=\"center\">答对</th>"
                "<th class=\"center\">选对</th><th class=\"center\">目标在提示词</th><th class=\"center\">目标披露形态</th>"
                "<th class=\"center\">Skills<br>Kept/Total</th><th class=\"center\">L2/L1/L0</th>"
                "<th class=\"center\">Skills<br>Budget-Tokens</th><th class=\"center\">Tokens-Out<br>/ Context-Size</th>"
                "<th class=\"center\">紧急截断</th><th class=\"center\">422</th><th>错误原文</th></tr></thead>")
        return f'<table class="compare-table">{head}<tbody>{rows}</tbody></table>'

    @staticmethod
    def _generate_skill_capacity_detail_html(all_results, out_dir, remote_mode=False, cmdline=""):
        """生成技能装载能力前沿的完整详情页(report_skill_capacity.html)。

        与 _generate_multi_backend_detail_html 同一范式：主报告只留能力矩阵卡片 +
        链接，二分搜索的完整曲线（每个 N 的判据与全部账本字段）、表述纪律与追溯、
        同分顺序病理、逐项检查记录全部下沉到本页。仅在本次运行确实产生了
        SKILL_CAPACITY 用例时才生成并返回 True，调用方据此决定是否渲染链接。
        """
        sc_results = [r for r in all_results if r.name.startswith("SKILL_CAPACITY:")]
        if not sc_results:
            return False

        frontiers = ReportGenerator._sc_collect_frontiers(all_results)
        matrix_html = (f'<table class="compare-table">{ReportGenerator._SC_CAPABILITY_HEADER}'
                       f'<tbody>{ReportGenerator._sc_capability_rows(frontiers)}</tbody></table>'
                       if frontiers else
                       '<div class="empty-state">本次未产生任何前沿搜索结果（可能因模型/配置缺失被精确跳过）</div>')

        curves_html = ""
        for model in sorted(frontiers):
            sections = ""
            for arm in ("legacy", "optimized"):
                entry = frontiers[model].get(arm)
                if not entry:
                    continue
                label = ReportGenerator._SC_ARM_LABEL.get(arm, arm)
                note = _html_escape(entry["note"]) if entry["note"] else ""
                note_html = (f'<div class="resp-detail" style="margin: -4px 0 8px;">{note}</div>'
                             if note else "")
                sections += (f'<div class="group-section"><div class="group-title">'
                             f'{_html_escape(label)} &middot; 前沿值 '
                             f'{ReportGenerator._sc_frontier_text(entry)[0]}（曲线 {len(entry["curve"])} 点，'
                             f'&#9733; 标记前沿点）</div>{note_html}'
                             f'{ReportGenerator._sc_curve_table_html(entry)}</div>')
            for arm in sorted(set(frontiers[model]) - {"legacy", "optimized"}):
                entry = frontiers[model][arm]
                sections += (f'<div class="group-section"><div class="group-title">'
                             f'{_html_escape(arm)}</div>'
                             f'{ReportGenerator._sc_curve_table_html(entry)}</div>')
            curves_html += (f'<div class="model-section"><h3 style="font-size: 15px; margin: 4px 0 10px;">'
                            f'{_html_escape(model)}</h3>{sections}</div>')
        if not curves_html:
            curves_html = '<div class="empty-state">本次未产生二分搜索曲线</div>'

        check_rows = ""
        for r in sc_results:
            if r.skipped:
                status_text, status_class = "SKIP", "skip"
            elif r.crashed:
                status_text, status_class = "CRASH", "crash"
            elif r.passed:
                status_text, status_class = "PASS", "pass"
            elif getattr(r, "ignorable", False):
                status_text, status_class = "IGN", "ignored"
            else:
                status_text, status_class = "FAIL", "fail"
            check_rows += f"""<tr>
                <td><code>{_html_escape(r.name)}</code></td>
                <td class="center"><span class="badge {status_class}">{status_text}</span></td>
                <td>{_html_escape(r.detail)}</td>
            </tr>"""
        checks_html = (f'<table class="compare-table"><thead><tr><th>用例</th><th class="center">状态</th>'
                       f'<th>详情</th></tr></thead><tbody>{check_rows}</tbody></table>')

        # Builder 真实驱动端到端确认（--skill_capacity_mode builder/both 才会产生）。
        # 背书边界的措辞按外部审查逐条收紧过：这条通道验证的是「由真实 QAIModelBuilder
        # 启动并运行的 GenieAPIService 实例在 N 上仍选对 + 答对」，**不**验证 Builder 的
        # 聊天协议/请求组帧/tools 注入/日志链路——因为容量池的 N 个合成 <available_skills>
        # 与自定义 tools 结构性无法经 Builder 聊天帧协议注入，请求只能直发服务端口。
        # 全部文案取自该用例 response_data 的 known_limitations，报告层不另写一份结论。
        builder_html = ""
        b_res = next((r for r in sc_results
                      if (r.response_data or {}).get("builder_e2e")), None)
        if b_res is not None:
            b = b_res.response_data or {}
            ev = b.get("evidence") or {}
            limits = "".join(f"<li>{_html_escape(str(x))}</li>"
                             for x in (b.get("known_limitations") or []))
            builder_html = f"""<div class="section">
<h2><span class="icon">&#128279;</span> Builder 真实驱动端到端确认（N={b.get('n')}）</h2>
<ul class="sc-note">
<li><strong>判定</strong>：选对={ev.get('picked')} / 答对={ev.get('answered')}；
<code>Skills-Kept/Total={ev.get('skills_kept')}/{ev.get('skills_total')}</code>、
<code>L2/L1/L0={ev.get('skills_l2')}/{ev.get('skills_l1')}/{ev.get('skills_l0')}</code>、
<code>Tokens-Out/Context={ev.get('tokens_out')}/{ev.get('context_size')}</code>。</li>
<li><strong>Builder 侧实测</strong>：<code>settings.auth.enabled={b.get('auth_enabled')}</code>
（未修改 Builder 任何源码）；Builder 拉起的真实命令行
<code>{_html_escape(str(b.get('builder_command')))}</code>；本次可观测账本字段
{_html_escape(str(b.get('ledger_headers_observed')))}。</li>
{limits}
</ul>
</div>"""

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>技能装载能力前沿 - 详细记录</title>
<style>
{ReportGenerator._common_css()}
.sc-note {{ margin: 0; padding-left: 20px; font-size: 13px; line-height: 1.75; color: var(--text-secondary); }}
.sc-note li {{ margin-bottom: 6px; }}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Skill Capacity Frontier Detail</div>
        <h1>技能装载能力前沿 &middot; 详细记录</h1>
        <p class="subtitle">二分搜索完整曲线、账本字段与表述纪律</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>模式:</strong> {"远程" if remote_mode else "本地"}</span>
            <span class="meta-item"><a href="report.html" style="color: var(--accent); text-decoration: none; border-bottom: 1px solid var(--accent); font-weight: 600;">← 返回总汇报</a></span>
            {ReportGenerator._cmdline_meta_html(cmdline)}
        </div>
    </div>
</div>

<div class="container">

<div class="section">
<h2><span class="icon">&#128202;</span> 能力矩阵（模型 &times; 改造前/后前沿值 &times; 保留率 &times; 上下文占用 &times; 提升倍数）</h2>
<div class="resp-detail" style="margin: -4px 0 10px;">前沿值 = 该档位下「同时装载 N 个技能仍能选对目标技能并答出其正文里唯一答案码」的最大 N（二分搜索求得，前沿点已用 &#9733; 标注在下方曲线里）。倍数只在两档均收敛且前沿点未预算饱和时给精确值，否则一律呈现为「&ge;N 下界」。</div>
{matrix_html}
</div>

<div class="section">
<h2><span class="icon">&#128207;</span> 表述纪律与追溯</h2>
{ReportGenerator._SC_DISCIPLINE_HTML}
</div>

<div class="section">
<h2><span class="icon">&#128200;</span> 二分搜索完整曲线</h2>
<div class="resp-detail" style="margin: -4px 0 10px;">「目标披露形态」取值 L2（全量条目）/ L1（摘要 + 触发条件）/ L0（仅名字 + 一行摘要）/ absent（未进最终提示词）；判据由目标 description 尾部唯一 canary 是否可见机械判定，不靠人工读日志。</div>
{curves_html}
</div>

<div class="section">
<h2><span class="icon">&#9878;</span> 同分顺序病理（独立结论，不参与容量倍数）</h2>
{ReportGenerator._SC_TIE_PATHOLOGY_HTML}
</div>

{builder_html}

<div class="section">
<h2><span class="icon">&#128203;</span> 逐项用例记录（{len(sc_results)}）</h2>
{checks_html}
</div>

<div class="footer">
    技能装载能力前沿详细记录 &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}
</div>

</div>
</body>
</html>"""

        ReportGenerator._assert_no_placeholder_leak(html, "技能装载前沿详情页 report_skill_capacity.html")
        out_path = Path(out_dir) / "report_skill_capacity.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] 技能装载前沿详情: {out_path}")
        return True

    @staticmethod
    def _crash_event_anchor(idx):
        return f"crash-{idx}"

    @staticmethod
    def _generate_crash_events_detail_html(crash_events, out_dir, remote_mode=False, cmdline=""):
        """生成崩溃事件的完整详情页(report_crash_events.html)。

        承载主报告/模型报告不适合展示的高密度内容——每条崩溃完整的进程 stderr/stdout
        尾部原始文本(默认展开)。主报告/模型报告只保留次数 + 逐条极简摘要(时间/模型/轮次/
        端点/详情,即已含人类可读退出码诊断的 detail 字段)+ 跳转到本页对应锚点的链接,
        与"多类型同时加载"下沉子报告的既有模式一致。仅在存在崩溃事件时才生成。
        """
        if not crash_events:
            return False
        rows_html = ""
        for idx, c in enumerate(crash_events):
            log_tail = getattr(c, "log_tail", "")
            log_tail_html = (f'<details open><summary>查看</summary><pre class="startup-detail">{_html_escape(log_tail)}</pre></details>'
                              if log_tail else "-")
            rows_html += f"""<tr id="{ReportGenerator._crash_event_anchor(idx)}">
                <td>{_html_escape(c.timestamp)}</td>
                <td>{_html_escape(c.model_name)}</td><td class="center">{c.round_num}</td>
                <td><code>{_html_escape(c.endpoint)}</code>{_crash_badge_html(c)}</td>
                <td>{_html_escape(c.detail)}</td>
                <td>{log_tail_html}</td>
            </tr>"""

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>崩溃事件 - 详细记录</title>
<style>
{ReportGenerator._common_css()}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Crash Events Detail</div>
        <h1>崩溃事件 &middot; 详细记录</h1>
        <p class="subtitle">全部崩溃事件的完整进程日志尾部</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>模式:</strong> {"远程" if remote_mode else "本地"}</span>
            <span class="meta-item"><a href="report.html" style="color: var(--accent); text-decoration: none; border-bottom: 1px solid var(--accent); font-weight: 600;">← 返回总汇报</a></span>
            {ReportGenerator._cmdline_meta_html(cmdline)}
        </div>
    </div>
</div>

<div class="container">

<div class="section">
<h2><span class="icon">&#9888;</span> 崩溃事件日志（{len(crash_events)}）</h2>
<table class="crash-table"><thead><tr>
    <th>时间</th><th>模型</th><th>轮次</th><th>端点</th><th>详情</th><th>进程日志尾部</th></tr></thead><tbody>
{rows_html}
</tbody></table>
</div>

<div class="footer">
    崩溃事件详细记录 &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}
</div>

</div>
</body>
</html>"""

        ReportGenerator._assert_no_placeholder_leak(html, "崩溃事件详情页 report_crash_events.html")
        out_path = Path(out_dir) / "report_crash_events.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] 崩溃事件详情: {out_path}")
        return True

    @staticmethod
    def _tool_call_anchor(idx):
        return f"toolcall-{idx}"

    @staticmethod
    def _generate_tool_calls_detail_html(toolcalls_results, out_dir, remote_mode=False, cmdline=""):
        """生成 tool_calls/function calling 协议测试的详情页(report_tool_calls.html)。

        承载这四个测试真正的诊断价值——工具调用数组结构、流式跨 chunk 重建后的
        arguments——而不是依赖通用的 chat/completions 子串匹配产出的空洞对话卡片
        (那条通用路径既不展示 response_data,也会与同一轮真正的 chat 测试发生锚点冲突)。
        主报告/模型报告只保留通过/跳过计数 + 跳转链接。
        """
        if not toolcalls_results:
            return False
        cards_html = ""
        for idx, r in enumerate(toolcalls_results):
            cls, txt, extra_badges = ReportGenerator._case_status_badge_html(r)
            payload_html = ""
            if r.response_data:
                payload_html = f'<pre class="startup-detail">{_html_escape(json.dumps(r.response_data, indent=2, ensure_ascii=False))}</pre>'
            elif r.text_response:
                payload_html = f'<div class="resp-detail">{_html_escape(r.text_response)}</div>'
            cards_html += f"""<div class="section" id="{ReportGenerator._tool_call_anchor(idx)}">
            <div class="conv-meta">
                <span class="model-tag">{_html_escape(r.model_name)}</span>
                <span class="round-tag">Round {r.round_num}</span>
                <span class="{cls}">{txt}</span>{extra_badges}
            </div>
            <h3 style="font-size: 14px; margin: 8px 0;">{_html_escape(r.name)}</h3>
            <div class="resp-detail">{_html_escape(r.detail)}</div>
            {payload_html}
            </div>"""

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>tool_calls 协议测试 - 详细记录</title>
<style>
{ReportGenerator._common_css()}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Tool Calls Protocol Detail</div>
        <h1>tool_calls 协议测试 &middot; 详细记录</h1>
        <p class="subtitle">每条测试的完整工具调用结构 / 流式重建后的 arguments</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>模式:</strong> {"远程" if remote_mode else "本地"}</span>
            <span class="meta-item"><a href="report.html" style="color: var(--accent); text-decoration: none; border-bottom: 1px solid var(--accent); font-weight: 600;">← 返回总汇报</a></span>
            {ReportGenerator._cmdline_meta_html(cmdline)}
        </div>
    </div>
</div>

<div class="container">
{cards_html}
<div class="footer">
    tool_calls 协议测试详细记录 &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}
</div>

</div>
</body>
</html>"""

        ReportGenerator._assert_no_placeholder_leak(html, "tool_calls 协议详情页 report_tool_calls.html")
        out_path = Path(out_dir) / "report_tool_calls.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] tool_calls 协议详情: {out_path}")
        return True

    @staticmethod
    def generate_summary_html(all_results, perf_data, crash_events, out_dir, remote_mode=False, suite_name="full", cmdline=""):
        """生成总汇报 HTML — 仅包含模型无关测试 + 性能对比汇总"""
        # 排除全部内部占位 model_name（_global_/_multi_model_ 等），只保留真实模型；
        # 统一复用 _is_internal_placeholder_model()，不要在这里再手写排除元组（详见其定义处注释）。
        model_names = sorted(set(r.model_name for r in all_results
                                 if not ReportGenerator._is_internal_placeholder_model(r.model_name)))
        multi_model_results = [r for r in all_results if r.model_name == "_multi_model_"]
        rounds = sorted(set(r.round_num for r in all_results))
        num_rounds = len(rounds)

        # 模型无关接口数据：优先使用 _global_ 的结果，否则回退到第一个真实模型的数据
        independent_results = [r for r in all_results
                               if r.name in ReportGenerator.MODEL_INDEPENDENT_ENDPOINTS
                               and r.model_name == "_global_"]
        if not independent_results and model_names:
            independent_results = [r for r in all_results
                                   if r.name in ReportGenerator.MODEL_INDEPENDENT_ENDPOINTS
                                   and r.model_name == model_names[0]]

        # 总计（仅统计模型无关测试用于总汇报）
        all_independent = [r for r in all_results if r.name in ReportGenerator.MODEL_INDEPENDENT_ENDPOINTS]
        # 去重：同一端点同一轮只保留第一个模型的结果
        seen = set()
        unique_independent = []
        for r in all_independent:
            key = (r.name, r.round_num)
            if key not in seen:
                seen.add(key)
                unique_independent.append(r)

        summary_ind = {"total": len(unique_independent), "passed": 0, "failed": 0, "crashed": 0, "skipped": 0}
        for r in unique_independent:
            if r.skipped:
                summary_ind["skipped"] += 1
            elif r.crashed:
                summary_ind["crashed"] += 1
            elif r.passed:
                summary_ind["passed"] += 1
            else:
                summary_ind["failed"] += 1

        # 全局统计（所有测试，用于顶部展示）
        summary_all = {"total": 0, "passed": 0, "failed": 0, "crashed": 0, "skipped": 0, "ignored": 0, "model_capability_issues": 0}
        for r in all_results:
            summary_all["total"] += 1
            if r.skipped:
                summary_all["skipped"] += 1
            elif r.crashed:
                summary_all["crashed"] += 1
            elif r.passed:
                summary_all["passed"] += 1
            else:
                summary_all["failed"] += 1
                if getattr(r, "ignorable", False):
                    summary_all["ignored"] += 1
            if getattr(r, "model_capability_issue", False):
                summary_all["model_capability_issues"] += 1
        pass_rate_all = (summary_all["passed"] / summary_all["total"] * 100) if summary_all["total"] > 0 else 0

        # 模型无关接口的透视表（只使用全局测试的轮次，通常只有 1 轮）
        independent_rounds = sorted(set(r.round_num for r in independent_results)) if independent_results else rounds
        independent_table = ReportGenerator._build_pivot_table(
            independent_results, ReportGenerator.MODEL_INDEPENDENT_ENDPOINTS, independent_rounds
        )

        # 性能对比表（合并原"跨模型推理对比"和"性能时序监控"）
        # 指标：avg prompt_processing_rate, avg token_generation_rate, avg CPU, avg Memory
        # 注意：排除 _multi_model_（阶段3多模型路由测试的占位名），它不产生 /profile 或推理性能数据，
        # 混入对比表只会出现一行全 N/A，没有意义。
        perf_compare_model_names = [m for m in model_names if m != "_multi_model_"]
        model_compare_html = ""
        if len(perf_compare_model_names) > 0:
            model_compare_html = """<div class="section">
            <h2><span class="icon">&#128200;</span> 性能对比</h2>
            <table class="compare-table">
            <thead><tr><th>模型</th><th>平均 Prompt 处理速率<br><small>(tokens/s)</small></th><th>平均 Token 生成速率<br><small>(tokens/s)</small></th><th>推理平均 CPU<br><small>(%)</small></th><th>推理平均内存<br><small>(MB)</small></th></tr></thead><tbody>"""
            for model in perf_compare_model_names:
                model_results = [r for r in all_results if r.model_name == model]

                # 从多轮 /profile 结果提取 prompt_processing_rate 和 token_generation_rate
                profile_results = [r for r in model_results
                                   if r.name == "GET /profile" and r.passed and r.response_data]
                ppr_values = []
                tgr_values = []
                for pr in profile_results:
                    try:
                        ppr = float(pr.response_data.get("prompt_processing_rate", 0))
                        if ppr > 0:
                            ppr_values.append(ppr)
                    except (ValueError, TypeError):
                        pass
                    try:
                        tgr = float(pr.response_data.get("token_generation_rate", 0))
                        if tgr > 0:
                            tgr_values.append(tgr)
                    except (ValueError, TypeError):
                        pass
                avg_ppr = (sum(ppr_values) / len(ppr_values)) if ppr_values else 0
                avg_tgr = (sum(tgr_values) / len(tgr_values)) if tgr_values else 0

                # 从推理结果的 perf_before/perf_after 提取 CPU 和内存
                _chat_names = set(ReportGenerator.MODEL_PERF_ENDPOINTS) - {"GET /profile"}
                chat_results = [r for r in model_results
                                if r.name in _chat_names
                                and r.passed]
                cpu_values = []
                mem_values = []
                for cr in chat_results:
                    if cr.perf_after and cr.perf_after.get("cpu_percent", 0) > 0:
                        # 展示层归一化：psutil 原始值以单核=100%计,MNN 等多线程后端跑满
                        # 多个核心时原始值可能远超100%(如700+%),反直觉;归一化为相对整机
                        # 总算力的百分比再展示,不影响 results.json 里保存的原始采样值。
                        cpu_values.append(_normalize_cpu_percent(cr.perf_after["cpu_percent"]))
                    if cr.perf_after and cr.perf_after.get("rss_mb", 0) > 0:
                        mem_values.append(cr.perf_after["rss_mb"])
                avg_cpu = (sum(cpu_values) / len(cpu_values)) if cpu_values else 0
                avg_mem = (sum(mem_values) / len(mem_values)) if mem_values else 0

                ppr_str = f"{avg_ppr:.1f}" if avg_ppr > 0 else "N/A"
                tgr_str = f"{avg_tgr:.1f}" if avg_tgr > 0 else "N/A"
                cpu_str = f"{avg_cpu:.1f}" if avg_cpu > 0 else "N/A"
                mem_str = f"{avg_mem:.0f}" if avg_mem > 0 else "N/A"
                model_compare_html += f"""<tr>
                    <td><strong>{_html_escape(model)}</strong></td>
                    <td class="center">{ppr_str}</td>
                    <td class="center">{tgr_str}</td>
                    <td class="center">{cpu_str}</td>
                    <td class="center">{mem_str}</td>
                </tr>"""
            model_compare_html += "</tbody></table></div>"

        # 多类型同时加载摘要：主报告只保留极简密度(通过/跳过计数 + 共存矩阵的短原因)，
        # 与其它区块保持一致；逐项检查记录、每个组合的完整失败原因(如 insufficient_memory
        # 的字节数明细)全部移至独立详情页,由 _generate_multi_backend_detail_html 生成。
        multi_backend_html = ""
        loaded_entries = []
        seen_loaded = set()
        for r in multi_model_results:
            for entry in (r.response_data or {}).get("loaded_models", []):
                key = (entry.get("id", ""), entry.get("backend", ""), entry.get("device", ""))
                if key not in seen_loaded:
                    seen_loaded.add(key)
                    loaded_entries.append(entry)
        if multi_model_results or loaded_entries:
            multi_pass = sum(1 for r in multi_model_results if r.passed)
            multi_skipped = sum(1 for r in multi_model_results if r.skipped)
            multi_crashed = sum(1 for r in multi_model_results if r.crashed)
            multi_total = len(multi_model_results)
            # 失败数 = 总数 - 通过 - 跳过 - 崩溃，与顶部全局汇总卡片(summary_all)的口径一致。
            multi_fail = multi_total - multi_pass - multi_skipped - multi_crashed
            device_types = sorted({entry.get("device") or "unknown" for entry in loaded_entries})

            has_detail_page = ReportGenerator._generate_multi_backend_detail_html(
                multi_model_results, loaded_entries, out_dir, remote_mode=remote_mode, cmdline=cmdline)

            loaded_rows = ""
            for entry in loaded_entries:
                loaded_rows += f"""<tr>
                    <td>{_html_escape(entry.get('id', ''))}</td>
                    <td><code>{_html_escape(entry.get('backend', ''))}</code></td>
                    <td><code>{_html_escape(entry.get('device', ''))}</code></td>
                    <td class=\"num\">{_html_escape(str(entry.get('context_length', '')))}</td>
                </tr>"""
            loaded_table_html = (f'<table class="compare-table"><thead><tr><th>模型</th><th>后端</th><th>设备</th><th>上下文</th></tr></thead><tbody>{loaded_rows}</tbody></table>'
                                  if loaded_rows else '<div class="empty-state">未捕获到已加载模型的 backend/device 明细</div>')

            # 后端共存矩阵：主报告只展示极短原因标签(如"内存不足,已跳过")，完整原始详情
            # (如 insufficient_memory 的字节数明细)在详情页的同名矩阵表格里。
            coexistence_html = ""
            matrix_result = next(
                (r for r in multi_model_results
                 if r.name == "MULTI: backend coexistence matrix (triple + pairwise fallback)"),
                None
            )
            if matrix_result and matrix_result.response_data and matrix_result.response_data.get("coexistence_matrix"):
                cm = matrix_result.response_data["coexistence_matrix"]
                _CM_STATUS_CLASS = {"pass": "status-pass", "fail": "status-fail",
                                     "skip": "status-skip", "unknown": "status-skip"}
                _CM_STATUS_TEXT = {"pass": "PASS", "fail": "FAIL", "skip": "SKIP", "unknown": "N/A"}
                _CM_PAIR_LABEL = {"npu+gpu": "QNN/NPU + GGUF/GPU", "npu+cpu": "QNN/NPU + MNN/CPU",
                                   "gpu+cpu": "GGUF/GPU + MNN/CPU"}
                triple = cm["triple"]
                triple_badge = f'<span class="{_CM_STATUS_CLASS.get(triple["status"], "status-skip")}">{_CM_STATUS_TEXT.get(triple["status"], triple["status"].upper())}</span>'
                pair_rows = ""
                for pair_key, pair_info in cm["pairs"].items():
                    p_status = pair_info["status"]
                    p_badge = f'<span class="{_CM_STATUS_CLASS.get(p_status, "status-skip")}">{_CM_STATUS_TEXT.get(p_status, p_status.upper())}</span>'
                    pair_rows += f"""<tr>
                        <td>{_html_escape(_CM_PAIR_LABEL.get(pair_key, pair_key))}</td>
                        <td class=\"center\">{p_badge}</td>
                        <td>{_html_escape(pair_info.get("reason", ""))}</td>
                    </tr>"""
                coexistence_html = f"""<h3 style=\"font-size: 15px; margin: 18px 0 10px;\">后端共存矩阵</h3>
                <table class=\"compare-table\"><thead><tr><th>组合</th><th class=\"center\">状态</th><th>原因</th></tr></thead><tbody>
                <tr><td><strong>三后端同时驻留</strong></td><td class=\"center\">{triple_badge}</td><td>{_html_escape(triple.get("reason", ""))}</td></tr>
                {pair_rows}
                </tbody></table>"""

            multi_fail_note_html = (
                f'<div style="color: var(--danger); font-size: 12px; font-weight: 600; margin-bottom: 6px;">'
                f'含 {multi_fail} 项失败，详见下方逐项检查记录</div>'
                if multi_fail > 0 else "")
            detail_link_html = (
                f'{multi_fail_note_html}<div class="model-link-card"><a href="report_multi_backend_coexistence.html">查看完整共存矩阵与逐项检查记录 →</a></div>'
                if has_detail_page else multi_fail_note_html)

            multi_backend_html = f"""<div class=\"section\">
            <h2><span class=\"icon\">&#129520;</span> 多类型同时加载</h2>
            <div class=\"summary-bar\">
                <div class=\"summary-card\"><div class=\"num\">{multi_total}</div><div class=\"label\">检查项</div></div>
                <div class=\"summary-card card-pass\"><div class=\"num\">{multi_pass}</div><div class=\"label\">通过</div></div>
                <div class=\"summary-card\"><div class=\"num\">{multi_skipped}</div><div class=\"label\">跳过</div></div>
                <div class=\"summary-card\"><div class=\"num\">{len(device_types)}</div><div class=\"label\">设备类型</div></div>
            </div>
            <h3 style=\"font-size: 15px; margin: 18px 0 10px;\">已加载 backend/device</h3>
            {loaded_table_html}
            {coexistence_html}
            {detail_link_html}
            </div>"""

        # 技能装载能力前沿（--suite skill_capacity）：主报告只保留能力矩阵卡片
        # （模型 × 改造前/后前沿值 × 提升倍数 × 保留率 × 上下文占用率）+ 指向详情页
        # 的链接，二分搜索完整曲线与表述纪律全部下沉到 report_skill_capacity.html，
        # 与"多类型同时加载"的下沉模式一致。倍数的可引用性由 _sc_gain_text() 按
        # usable_for_gain_ratio 机械判定，报告层不做任何数值硬编码。
        skill_capacity_html = ""
        sc_results = [r for r in all_results if r.name.startswith("SKILL_CAPACITY:")]
        if sc_results:
            has_sc_detail = ReportGenerator._generate_skill_capacity_detail_html(
                all_results, out_dir, remote_mode=remote_mode, cmdline=cmdline)
            sc_frontiers = ReportGenerator._sc_collect_frontiers(all_results)
            sc_pass = sum(1 for r in sc_results if r.passed)
            sc_skipped = sum(1 for r in sc_results if r.skipped)
            sc_crashed = sum(1 for r in sc_results if r.crashed)
            sc_fail = len(sc_results) - sc_pass - sc_skipped - sc_crashed
            sc_matrix_html = (
                f'<table class="compare-table">{ReportGenerator._SC_CAPABILITY_HEADER}'
                f'<tbody>{ReportGenerator._sc_capability_rows(sc_frontiers)}</tbody></table>'
                if sc_frontiers else
                '<div class="empty-state">本次未产生前沿搜索结果（模型或配置缺失时按设计精确跳过，不伪造数字）</div>')
            sc_fail_note_html = (
                f'<div style="color: var(--danger); font-size: 12px; font-weight: 600; margin-bottom: 6px;">'
                f'含 {sc_fail} 项失败，详见详情页逐项用例记录</div>'
                if sc_fail > 0 else "")
            sc_link_html = (
                f'{sc_fail_note_html}<div class="model-link-card"><a href="report_skill_capacity.html">查看二分搜索完整曲线、表述纪律与同分顺序病理 →</a></div>'
                if has_sc_detail else sc_fail_note_html)
            # Builder 端到端确认的一行摘要。措辞按外部审查收紧：只说「由真实 Builder
            # 启动并运行的服务实例在 N 上仍选对+答对」，绝不写成「已由 Builder 链路
            # 端到端确认」——那会被读成 Builder 的聊天/转发链路也被覆盖，而实测请求
            # 是直发服务端口的（Builder 在请求面已退出因果链）。
            sc_builder_note_html = ""
            b_res = next((r for r in sc_results if (r.response_data or {}).get("builder_e2e")), None)
            if b_res is not None:
                b = b_res.response_data or {}
                bev = b.get("evidence") or {}
                sc_builder_note_html = (
                    f'<div class="resp-detail" style="margin: 8px 0 0;">'
                    f'<strong>Builder 真实驱动端到端确认</strong>：由真实 QAIModelBuilder 启动并运行的 '
                    f'GenieAPIService 实例，在 N={b.get("n")} 上选对={bev.get("picked")} / '
                    f'答对={bev.get("answered")}（<code>settings.auth.enabled='
                    f'{b.get("auth_enabled")}</code>，未修改 Builder 源码）。'
                    f'该确认<strong>不覆盖</strong> Builder 自身的聊天协议 / 请求组帧 / tools 注入 / '
                    f'日志链路——容量池的合成 <code>&lt;available_skills&gt;</code> 与自定义 '
                    f'<code>tools</code> 无法经 Builder 聊天帧协议注入，验证请求为直发服务端口。</div>')
            skill_capacity_html = f"""<div class="section">
            <h2><span class="icon">&#128202;</span> 技能装载能力前沿（能力矩阵）</h2>
            <div class="summary-bar">
                <div class="summary-card"><div class="num">{len(sc_results)}</div><div class="label">用例数</div></div>
                <div class="summary-card card-pass"><div class="num">{sc_pass}</div><div class="label">通过</div></div>
                <div class="summary-card card-fail"><div class="num">{sc_fail}</div><div class="label">失败</div></div>
                <div class="summary-card card-crash"><div class="num">{sc_crashed}</div><div class="label">崩溃</div></div>
                <div class="summary-card"><div class="num">{sc_skipped}</div><div class="label">跳过</div></div>
            </div>
            <div class="resp-detail" style="margin: 4px 0 10px;">前沿值 = 该档位下「同时装载 N 个技能仍能选对目标技能并答出其正文里唯一答案码」的最大 N。提升倍数只在两档均收敛（converged）且前沿点未预算饱和时给精确值，否则一律呈现为「&ge;N 下界」；采样次数见「模型」列，<strong>repeat=1 时未做重复性检验，只能表述为「效应量极大且方向明确」，不声称统计显著</strong>。</div>
            {sc_matrix_html}
            {sc_builder_note_html}
            {sc_link_html}
            </div>"""

        # 模型列表（带链接）
        model_links_html = '<div class="section"><h2><span class="icon">&#128218;</span> 详细报告</h2>'
        for model in model_names:
            model_results = [r for r in all_results if r.model_name == model]
            m_pass = sum(1 for r in model_results if r.passed)
            m_total = len(model_results)
            m_rate = (m_pass / m_total * 100) if m_total > 0 else 0
            safe_model_name = model.replace(" ", "_").replace("/", "_")
            model_links_html += f"""<div class="model-link-card">
                <a href="report_{safe_model_name}.html">{_html_escape(model)}</a>
                <div class="model-link-stats">
                    <span class="stat-pass">{m_pass}/{m_total} 通过</span>
                    <span class="stat-rate">{m_rate:.0f}%</span>
                </div>
            </div>"""
        model_links_html += '</div>'

        # 崩溃日志：主报告只保留次数 + 逐条极简摘要(时间/模型/轮次/端点/detail 里已含的人类可读
        # 退出码诊断),完整 stderr/stdout 尾部原始文本下沉到 report_crash_events.html,
        # 与"多类型同时加载"的下沉模式一致，避免主报告体积随崩溃数量无上限增长。
        has_crash_detail_page = ReportGenerator._generate_crash_events_detail_html(
            crash_events, out_dir, remote_mode=remote_mode, cmdline=cmdline)
        crash_html = ""
        if crash_events:
            crash_html = """<div class="section"><h2><span class="icon">&#9888;</span> 崩溃事件日志</h2>
            <table class="crash-table"><thead><tr>
                <th>时间</th><th>模型</th><th>轮次</th><th>端点</th><th>详情</th><th>完整日志</th></tr></thead><tbody>"""
            for idx, c in enumerate(crash_events):
                detail_link = (f'<a href="report_crash_events.html#{ReportGenerator._crash_event_anchor(idx)}">查看 →</a>'
                                if has_crash_detail_page else "-")
                crash_html += f"""<tr><td>{_html_escape(c.timestamp)}</td>
                    <td>{_html_escape(c.model_name)}</td><td class="center">{c.round_num}</td>
                    <td><code>{_html_escape(c.endpoint)}</code>{_crash_badge_html(c)}</td><td>{_html_escape(c.detail)}</td>
                    <td>{detail_link}</td></tr>"""
            crash_html += "</tbody></table></div>"

        # MNN 内存容错统计块：区分"MNN 自身真实 OOM"(MNN_OOM_CRASH)与"疑似因 MNN OOM 拖垮进程而
        # 级联崩溃的其它后端"(MNN_OOM_CASCADE)。两者都是真实问题、都已计入 failed/crashed 统计——
        # 级联受累计数不再代表豁免，只是一个诊断性提示，提醒人工去排查这是否是一个需要单独修复的
        # 真实级联崩溃 bug（例如共享状态未隔离），而不是把它当作可以放行的"环境限制"。
        mnn_self_oom_events = [c for c in crash_events if c.endpoint == "MNN_OOM_CRASH"]
        mnn_cascade_events = [c for c in crash_events if c.endpoint == "MNN_OOM_CASCADE"]
        auto_restarted_count = sum(1 for r in all_results if getattr(r, "auto_restarted", False))
        mnn_html = ""
        if mnn_self_oom_events or mnn_cascade_events or auto_restarted_count > 0:
            mnn_html = f"""<div class="section"><h2><span class="icon">&#128202;</span> MNN 内存容错统计</h2>
            <div class="summary-bar">
                <div class="summary-card card-crash"><div class="num">{len(mnn_self_oom_events)}</div><div class="label">MNN 自身真实 OOM</div></div>
                <div class="summary-card card-crash" title="该计数不代表豁免，均已计入上方总的 failed/crashed 统计；仅作诊断提示，建议人工排查是否为需要单独修复的真实级联崩溃 bug"><div class="num">{len(mnn_cascade_events)}</div><div class="label">疑似 MNN OOM 级联崩溃(已计入失败)</div></div>
                <div class="summary-card card-pass"><div class="num">{auto_restarted_count}</div><div class="label">自动恢复次数</div></div>
            </div>
            </div>"""

        # 服务启动失败的醒目横幅 — 只要存在任何 endpoint == "SERVICE_STARTUP" 的事件
        # 就在报告最顶部显示一条红色横幅,把模型、详情、stderr 日志路径都列出来。
        startup_failures = [c for c in crash_events if c.endpoint == "SERVICE_STARTUP"]
        startup_banner_html = ""
        if startup_failures:
            startup_banner_html = '<div class="startup-banner"><div class="startup-banner-title">⚠ 检测到 ' + str(len(startup_failures)) + ' 次服务启动失败</div>'
            startup_banner_html += '<div class="startup-banner-desc">GenieAPIService.exe 在调用 <code>Popen</code> 后 2 秒内立即退出,导致服务从未真正监听端口。常见原因:架构不匹配 (x86-64 host vs ARM64 exe)、缺少 QNN/VC 运行时 DLL、OneDrive 占位文件未下载、模型配置路径错误。请先看 stderr 日志再继续。</div>'
            startup_banner_html += '<table class="startup-table"><thead><tr><th>时间</th><th>模型</th><th>失败详情 (含 exit_code / stderr 摘要)</th></tr></thead><tbody>'
            for c in startup_failures:
                startup_banner_html += f'<tr><td>{_html_escape(c.timestamp)}</td><td>{_html_escape(c.model_name)}</td><td><pre class="startup-detail">{_html_escape(c.detail)}</pre></td></tr>'
            startup_banner_html += '</tbody></table></div>'

        matrix_html = ReportGenerator._build_completeness_matrix(all_results, model_names, suite_name)

        # 独立的 Builder 集成 / SampleApp 明细区块：不再仅仅体现为完备性矩阵里的一个格子。
        # Builder 集成用例的占位 model_name 这里不按 model_names 过滤，确保它们也能在总汇报
        # 里被看到明细，而不是完全依赖每模型报告页面。
        builder_results = [r for r in all_results if r.name.startswith("BUILDER")]
        sampleapp_results = [r for r in all_results if r.name.startswith("SAMPLEAPP:")]
        builder_section_html = ""
        if builder_results:
            builder_total = len(builder_results)
            builder_pass = sum(1 for r in builder_results if r.passed)
            builder_skipped = sum(1 for r in builder_results if r.skipped)
            builder_crashed = sum(1 for r in builder_results if r.crashed)
            # 失败数 = 总数 - 通过 - 跳过 - 崩溃，与顶部全局汇总卡片(summary_all)的口径一致。
            builder_fail = builder_total - builder_pass - builder_skipped - builder_crashed

            builder_fail_note_html = (
                f'<div style="color: var(--danger); font-size: 12px; font-weight: 600; margin-bottom: 6px;">'
                f'含 {builder_fail} 项失败，详见每模型报告页面</div>'
                if builder_fail > 0 else "")

            builder_section_html = f"""<div class="section"><h2><span class="icon">&#128295;</span> Builder 集成测试结果</h2>
            <div class="summary-bar">
                <div class="summary-card"><div class="num">{builder_total}</div><div class="label">用例数</div></div>
                <div class="summary-card card-pass"><div class="num">{builder_pass}</div><div class="label">通过</div></div>
                <div class="summary-card card-fail"><div class="num">{builder_fail}</div><div class="label">失败</div></div>
                <div class="summary-card card-crash"><div class="num">{builder_crashed}</div><div class="label">崩溃</div></div>
                <div class="summary-card"><div class="num">{builder_skipped}</div><div class="label">跳过</div></div>
            </div>
            {builder_fail_note_html}
            </div>"""
        sampleapp_section_html = ""
        if sampleapp_results:
            # 主报告只保留摘要计数(与 Builder 摘要卡片同一写法);完整逐用例明细表只在
            # 每个模型报告(model_sampleapp_html)里保留一份，避免同一份数据被重复渲染两遍。
            sampleapp_total = len(sampleapp_results)
            sampleapp_pass = sum(1 for r in sampleapp_results if r.passed)
            sampleapp_skipped = sum(1 for r in sampleapp_results if r.skipped)
            sampleapp_crashed = sum(1 for r in sampleapp_results if r.crashed)
            sampleapp_fail = sampleapp_total - sampleapp_pass - sampleapp_skipped - sampleapp_crashed

            sampleapp_fail_note_html = (
                f'<div style="color: var(--danger); font-size: 12px; font-weight: 600; margin-bottom: 6px;">'
                f'含 {sampleapp_fail} 项失败，详见每模型报告页面</div>'
                if sampleapp_fail > 0 else "")

            sampleapp_section_html = f"""<div class="section"><h2><span class="icon">&#128241;</span> SampleApp 测试结果</h2>
            <div class="summary-bar">
                <div class="summary-card"><div class="num">{sampleapp_total}</div><div class="label">用例数</div></div>
                <div class="summary-card card-pass"><div class="num">{sampleapp_pass}</div><div class="label">通过</div></div>
                <div class="summary-card card-fail"><div class="num">{sampleapp_fail}</div><div class="label">失败</div></div>
                <div class="summary-card card-crash"><div class="num">{sampleapp_crashed}</div><div class="label">崩溃</div></div>
                <div class="summary-card"><div class="num">{sampleapp_skipped}</div><div class="label">跳过</div></div>
            </div>
            {sampleapp_fail_note_html}
            </div>"""

        # tool_calls/function calling 协议测试：独立分类区块，不再混入模型报告的"其它/专项
        # 测试"兜底大杂烩；完整协议载荷(工具调用数组、流式重建后的 arguments)下沉到
        # report_tool_calls.html，主报告只保留计数 + 跳转链接。
        toolcalls_results = [r for r in all_results if r.name.startswith("POST /v1/chat/completions (tool_call")]
        toolcalls_section_html = ""
        if toolcalls_results:
            tc_total = len(toolcalls_results)
            tc_pass = sum(1 for r in toolcalls_results if r.passed)
            tc_skipped = sum(1 for r in toolcalls_results if r.skipped)
            tc_crashed = sum(1 for r in toolcalls_results if r.crashed)
            tc_fail = tc_total - tc_pass - tc_skipped - tc_crashed

            has_toolcalls_detail_page = ReportGenerator._generate_tool_calls_detail_html(
                toolcalls_results, out_dir, remote_mode=remote_mode, cmdline=cmdline)
            toolcalls_link_html = ('<div style="margin-top: 6px;"><a href="report_tool_calls.html">查看完整协议详情 →</a></div>'
                                    if has_toolcalls_detail_page else "")
            tc_fail_note_html = (
                f'<div style="color: var(--danger); font-size: 12px; font-weight: 600; margin-bottom: 6px;">'
                f'含 {tc_fail} 项失败，详见协议详情页</div>'
                if tc_fail > 0 else "")

            toolcalls_section_html = f"""<div class="section"><h2><span class="icon">&#128268;</span> tool_calls 协议测试</h2>
            <div class="summary-bar">
                <div class="summary-card"><div class="num">{tc_total}</div><div class="label">用例数</div></div>
                <div class="summary-card card-pass"><div class="num">{tc_pass}</div><div class="label">通过</div></div>
                <div class="summary-card card-fail"><div class="num">{tc_fail}</div><div class="label">失败</div></div>
                <div class="summary-card card-crash"><div class="num">{tc_crashed}</div><div class="label">崩溃</div></div>
                <div class="summary-card"><div class="num">{tc_skipped}</div><div class="label">跳过(模型能力局限)</div></div>
            </div>
            {tc_fail_note_html}
            {toolcalls_link_html}
            </div>"""
        graceful_shutdown_results = [r for r in all_results if r.name.startswith("GRACEFUL_SHUTDOWN:")]
        graceful_shutdown_section_html = ""
        if graceful_shutdown_results:
            graceful_shutdown_section_html = f"""<div class="section"><h2><span class="icon">&#9203;</span> 推理中终止进程 → 优雅退出验证</h2>
            <div class="resp-detail" style="margin: -4px 0 10px;">对三种后端各选一个代表模型，在其处理长耗时推理请求期间发送终止信号，验证进程能走既有的关闭逻辑正常退出（日志出现优雅关闭标记且退出码不匹配任何已知 Windows 崩溃特征码），而不是被系统判定为异常崩溃。</div>
            {ReportGenerator._build_case_detail_table(graceful_shutdown_results)}
            </div>"""
        cmdline_html = ReportGenerator._cmdline_meta_html(cmdline)

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        total_latency = sum(r.latency_ms for r in all_results if not r.skipped)

        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>GenieAPIService 测试总汇报 - {now_str}</title>
<style>
{ReportGenerator._common_css()}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Genie API Service · Integration Suite</div>
        <h1>GenieAPIService 集成测试总汇报</h1>
        <p class="subtitle">API Integration Test Summary Report</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>测试模型:</strong> {len(model_names)} 个</span>
            <span class="meta-item"><strong>测试轮数:</strong> {num_rounds}</span>
            <span class="meta-item"><strong>总耗时:</strong> {total_latency/1000:.1f}s</span>
            <span class="meta-item"><strong>模式:</strong> {'远程' if remote_mode else '本地'}</span>
            <span class="meta-item"><strong>测试套件:</strong> {_html_escape(suite_name)}</span>
            {cmdline_html}
        </div>
    </div>
</div>

<div class="container">

{startup_banner_html}

<div class="summary-bar">
    <div class="summary-card"><div class="num">{summary_all['total']}</div><div class="label">总测试数</div></div>
    <div class="summary-card card-pass"><div class="num">{summary_all['passed']}</div><div class="label">通过</div></div>
    <div class="summary-card card-fail"><div class="num">{summary_all['failed']}</div><div class="label">失败</div></div>
    <div class="summary-card card-ignored" title="服务端已知占位/未实现缺陷的 FAIL 子集 (501、占位 400 等); failed 数已包含这些条目, 这里只是单独标出来"><div class="num">{summary_all['ignored']}</div><div class="label">可忽略</div></div>
    <div class="summary-card card-crash"><div class="num">{summary_all['crashed']}</div><div class="label">崩溃</div></div>
    <div class="summary-card"><div class="num">{summary_all['skipped']}</div><div class="label">跳过</div></div>
    <div class="summary-card card-capability" title="根因判定为模型自身能力/输出质量局限而非服务端缺陷的诊断性标注(如重复出词、tool_calls 未按指令触发);诊断性维度,不改变 passed/failed/退出码判定"><div class="num">{summary_all['model_capability_issues']}</div><div class="label">模型能力问题</div></div>
</div>

<div class="progress-bar">
    <div class="progress-fill {'good' if pass_rate_all >= 80 else ('warn' if pass_rate_all >= 50 else 'bad')}" style="width:{max(pass_rate_all, 5):.0f}%">
        <span class="progress-text">通过率 {pass_rate_all:.1f}%</span>
    </div>
</div>
<div class="progress-meta"><span>总体通过率</span><span class="pct">{pass_rate_all:.1f}%</span></div>

<div class="section">
<h2><span class="icon">&#128269;</span> 通用接口测试（模型无关）</h2>
<div class="model-section">
    <div class="group-section">
        {independent_table}
    </div>
</div>
</div>

{model_compare_html}
{multi_backend_html}
{skill_capacity_html}
{model_links_html}
{matrix_html}
{builder_section_html}
{sampleapp_section_html}
{toolcalls_section_html}
{graceful_shutdown_section_html}
{mnn_html}
{crash_html}

<div class="footer">
    GenieAPIService Integration Test Summary &middot; Generated by test_service.py &middot; {now_str}
</div>

</div>
</body>
</html>"""

        ReportGenerator._assert_no_placeholder_leak(html, "总汇报 report.html")
        out_path = Path(out_dir) / "report.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] 总汇报 HTML: {out_path}")

    @staticmethod
    def generate_model_reports(all_results, perf_data, crash_events, out_dir, remote_mode=False, cmdline=""):
        """为每个模型生成独立的 HTML 报告"""
        # 排除全部内部占位 model_name（_global_/_multi_model_ 等），只为真实模型生成报告；
        # 统一复用 _is_internal_placeholder_model()，不要在这里再手写排除元组（详见其定义处注释）。
        model_names = sorted(set(r.model_name for r in all_results
                                 if not ReportGenerator._is_internal_placeholder_model(r.model_name)))
        rounds = sorted(set(r.round_num for r in all_results))
        # 与 generate_summary_html._generate_crash_events_detail_html 共用同一份 crash_events
        # 列表(同一批 CrashEvent 对象),用对象身份映射到全局下标,保证本页链接的锚点与
        # report_crash_events.html(由总汇报流程先行生成)里的锚点完全对应。
        crash_idx_by_id = {id(c): idx for idx, c in enumerate(crash_events)}
        # 与 generate_summary_html._generate_tool_calls_detail_html 共用同一份 tool_calls 测试
        # 结果(同一批 TestResult 对象),用对象身份映射到全局下标,道理与上面的崩溃事件映射一致。
        all_toolcalls_results = [r for r in all_results if r.name.startswith("POST /v1/chat/completions (tool_call")]
        toolcalls_idx_by_id = {id(r): idx for idx, r in enumerate(all_toolcalls_results)}

        for model in model_names:
            model_results = [r for r in all_results if r.model_name == model]
            model_crashes = [c for c in crash_events if c.model_name == model]

            m_pass = sum(1 for r in model_results if r.passed)
            m_total = len(model_results)
            m_rate = (m_pass / m_total * 100) if m_total > 0 else 0

            # 推理性能组
            perf_endpoints = ReportGenerator.MODEL_PERF_ENDPOINTS
            perf_results = [r for r in model_results if r.name in perf_endpoints]
            perf_table = ReportGenerator._build_pivot_table(perf_results, perf_endpoints, rounds)

            # 服务功能组（模型相关但非推理的接口）
            service_endpoints = [ep for ep in ReportGenerator.MODEL_DEPENDENT_ENDPOINTS
                                 if ep not in perf_endpoints]
            service_results = [r for r in model_results if r.name in service_endpoints]
            service_table = ReportGenerator._build_pivot_table(service_results, service_endpoints, rounds)

            # 其它/专项测试组：动态兜底展示未被上面两组名单覆盖的结果(多模态用例、GGUF 显式加载明细、
            # SampleApp/Builder 集成用例等),避免"计入总数但明细表里找不到对应行"的数据黑洞。
            # BUILDER/SAMPLEAPP 用例已拆到下方独立明细区块,这里提前排除,避免在通用兜底表里重复展示。
            leftover_endpoints = sorted(
                set(r.name for r in model_results) - set(perf_endpoints) - set(service_endpoints)
                - {r.name for r in model_results if r.name.startswith("BUILDER") or r.name.startswith("SAMPLEAPP:")
                   or r.name.startswith("POST /v1/chat/completions (tool_call")}
            )
            leftover_table = ReportGenerator._build_pivot_table(model_results, leftover_endpoints, rounds)

            # 独立的 Builder 集成 / SampleApp 明细区块（模型级）：与总汇报保持同一套展示逻辑，
            # 不再混在通用的"其它/专项测试"兜底表里。
            model_builder_results = [r for r in model_results if r.name.startswith("BUILDER")]
            model_sampleapp_results = [r for r in model_results if r.name.startswith("SAMPLEAPP:")]
            model_builder_html = ""
            if model_builder_results:
                model_builder_html = f"""<div class="section"><h2><span class="icon">&#128295;</span> Builder 集成测试结果</h2>
                {ReportGenerator._build_case_detail_table(model_builder_results, show_model_column=False)}
                </div>"""
            model_sampleapp_html = ""
            if model_sampleapp_results:
                model_sampleapp_html = f"""<div class="section"><h2><span class="icon">&#128241;</span> SampleApp 测试结果</h2>
                {ReportGenerator._build_case_detail_table(model_sampleapp_results, show_model_column=False)}
                </div>"""

            # tool_calls 协议测试（模型级）：独立分类区块，不再落入上面的"其它/专项测试"兜底表；
            # 完整协议载荷统一在共享的 report_tool_calls.html 里查看(见 crash_idx_by_id 同一套映射手法)。
            model_toolcalls_results = [r for r in model_results if r.name.startswith("POST /v1/chat/completions (tool_call")]
            model_toolcalls_html = ""
            if model_toolcalls_results:
                tc_total = len(model_toolcalls_results)
                tc_pass = sum(1 for r in model_toolcalls_results if r.passed)
                tc_skipped = sum(1 for r in model_toolcalls_results if r.skipped)
                tc_crashed = sum(1 for r in model_toolcalls_results if r.crashed)
                tc_fail = tc_total - tc_pass - tc_skipped - tc_crashed
                tc_links = []
                for r in model_toolcalls_results:
                    idx = toolcalls_idx_by_id.get(id(r))
                    if idx is not None:
                        tc_links.append(f'<a href="report_tool_calls.html#{ReportGenerator._tool_call_anchor(idx)}">R{r.round_num}: {_html_escape(r.name)} →</a>')
                tc_links_html = "<br>".join(tc_links) if tc_links else ""
                model_toolcalls_html = f"""<div class="section"><h2><span class="icon">&#128268;</span> tool_calls 协议测试</h2>
                <div class="summary-bar">
                    <div class="summary-card"><div class="num">{tc_total}</div><div class="label">用例数</div></div>
                    <div class="summary-card card-pass"><div class="num">{tc_pass}</div><div class="label">通过</div></div>
                    <div class="summary-card card-fail"><div class="num">{tc_fail}</div><div class="label">失败</div></div>
                    <div class="summary-card card-crash"><div class="num">{tc_crashed}</div><div class="label">崩溃</div></div>
                    <div class="summary-card"><div class="num">{tc_skipped}</div><div class="label">跳过(模型能力局限)</div></div>
                </div>
                <div class="resp-detail">{tc_links_html}</div>
                </div>"""

            # 性能报告：每一轮 /profile 的完整数据 + CPU/内存
            perf_report_html = ""
            profile_results = [r for r in model_results
                               if r.name == "GET /profile" and r.passed and r.response_data]
            # 收集每轮的 chat 推理结果用于提取 CPU/内存
            chat_by_round = {}
            _chat_names = set(ReportGenerator.MODEL_PERF_ENDPOINTS) - {"GET /profile"}
            for cr in model_results:
                if cr.name in _chat_names and cr.passed:
                    chat_by_round.setdefault(cr.round_num, []).append(cr)

            def _fmt(val):
                if val == "N/A" or val is None:
                    return "N/A"
                try:
                    return f"{float(val):.2f}"
                except (ValueError, TypeError):
                    return str(val)

            def _fmt_int(val):
                if val == "N/A" or val is None:
                    return "N/A"
                try:
                    return str(int(float(val)))
                except (ValueError, TypeError):
                    return str(val)

            if profile_results:
                perf_report_html = """<div class="section">
                <h2><span class="icon">&#128202;</span> 性能报告</h2>
                <p style="color: var(--text-secondary); margin-bottom: 18px; font-size: 13px;">每轮推理后 <code>/profile</code> 返回的详细性能指标及资源占用</p>
                <div class="perf-round-grid">"""
                for pr in profile_results:
                    ttft = pr.response_data.get("time_to_first_token", "N/A")
                    tgt = pr.response_data.get("token_generation_time", "N/A")
                    ppr = pr.response_data.get("prompt_processing_rate", "N/A")
                    tgr = pr.response_data.get("token_generation_rate", "N/A")
                    npt = pr.response_data.get("num_prompt_tokens", "N/A")
                    ngt = pr.response_data.get("num_generated_tokens", "N/A")
                    # 从该轮 chat 结果提取 CPU/内存
                    round_chats = chat_by_round.get(pr.round_num, [])
                    # 展示层归一化,原因同总汇报的性能对比表(见 _normalize_cpu_percent 定义处注释)。
                    cpu_vals = [_normalize_cpu_percent(c.perf_after["cpu_percent"]) for c in round_chats
                                if c.perf_after and c.perf_after.get("cpu_percent", 0) > 0]
                    mem_vals = [c.perf_after["rss_mb"] for c in round_chats
                                if c.perf_after and c.perf_after.get("rss_mb", 0) > 0]
                    avg_cpu = (sum(cpu_vals) / len(cpu_vals)) if cpu_vals else None
                    avg_mem = (sum(mem_vals) / len(mem_vals)) if mem_vals else None
                    cpu_str = f"{avg_cpu:.1f}%" if avg_cpu else "N/A"
                    mem_str = f"{avg_mem:.0f} MB" if avg_mem else "N/A"
                    perf_report_html += f"""
                <div class="perf-round-card">
                    <div class="perf-round-title">Round {pr.round_num}</div>
                    <div class="perf-metric"><span class="perf-metric-label">Time to First Token (ms)</span><span class="perf-metric-value">{_fmt(ttft)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">Token Generation Time (ms)</span><span class="perf-metric-value">{_fmt(tgt)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">Prompt Processing Rate (tokens/s)</span><span class="perf-metric-value">{_fmt(ppr)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">Token Generation Rate (tokens/s)</span><span class="perf-metric-value">{_fmt(tgr)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">Num Prompt Tokens</span><span class="perf-metric-value">{_fmt_int(npt)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">Num Generated Tokens</span><span class="perf-metric-value">{_fmt_int(ngt)}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">推理 CPU 占用</span><span class="perf-metric-value">{cpu_str}</span></div>
                    <div class="perf-metric"><span class="perf-metric-label">推理内存占用</span><span class="perf-metric-value">{mem_str}</span></div>
                </div>"""
                perf_report_html += "</div></div>"
            else:
                perf_report_html = """<div class="section">
                <h2><span class="icon">&#128202;</span> 性能报告</h2>
                <div class="empty-state">无 /profile 数据（模型未返回性能指标）</div>
                </div>"""

            # 崩溃日志:只保留次数 + 逐条极简摘要 + 跳转链接,完整 stderr/stdout 尾部原始文本
            # 在 report_crash_events.html(见 generate_summary_html 的下沉逻辑)。
            crash_html = ""
            if model_crashes:
                crash_html = """<div class="section"><h2><span class="icon">&#9888;</span> 崩溃事件</h2>
                <table class="crash-table"><thead><tr>
                    <th>时间</th><th>轮次</th><th>端点</th><th>详情</th><th>完整日志</th></tr></thead><tbody>"""
                for c in model_crashes:
                    idx = crash_idx_by_id.get(id(c))
                    detail_link = (f'<a href="report_crash_events.html#{ReportGenerator._crash_event_anchor(idx)}">查看 →</a>'
                                    if idx is not None else "-")
                    crash_html += f"""<tr><td>{_html_escape(c.timestamp)}</td>
                        <td class="center">{c.round_num}</td>
                        <td><code>{_html_escape(c.endpoint)}</code>{_crash_badge_html(c)}</td><td>{_html_escape(c.detail)}</td>
                        <td>{detail_link}</td></tr>"""
                crash_html += "</tbody></table></div>"

            # 服务启动失败的醒目横幅 (模型级)
            model_startup_failures = [c for c in model_crashes if c.endpoint == "SERVICE_STARTUP"]
            startup_banner_html = ""
            if model_startup_failures:
                startup_banner_html = '<div class="startup-banner"><div class="startup-banner-title">⚠ 服务启动失败 — 本模型未能运行任何测试</div>'
                startup_banner_html += '<div class="startup-banner-desc">GenieAPIService.exe 启动后立即退出。下表展示具体的 exit_code 与 stderr 日志摘要。</div>'
                startup_banner_html += '<table class="startup-table"><thead><tr><th>时间</th><th>失败详情</th></tr></thead><tbody>'
                for c in model_startup_failures:
                    startup_banner_html += f'<tr><td>{_html_escape(c.timestamp)}</td><td><pre class="startup-detail">{_html_escape(c.detail)}</pre></td></tr>'
                startup_banner_html += '</tbody></table></div>'

            now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
            total_latency = sum(r.latency_ms for r in model_results if not r.skipped)

            html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>{_html_escape(model)} - 测试报告</title>
<style>
{ReportGenerator._common_css()}
</style>
</head>
<body>
<div class="header">
    <div class="header-inner">
        <div class="eyebrow">Model Test Report</div>
        <h1>{_html_escape(model)}</h1>
        <p class="subtitle">模型测试详细报告</p>
        <div class="meta">
            <span class="meta-item"><strong>生成时间:</strong> {now_str}</span>
            <span class="meta-item"><strong>测试轮数:</strong> {len(rounds)}</span>
            <span class="meta-item"><strong>总耗时:</strong> {total_latency/1000:.1f}s</span>
            <span class="meta-item"><a href="report.html" style="color: var(--accent); text-decoration: none; border-bottom: 1px solid var(--accent); font-weight: 600;">← 返回总汇报</a></span>
            {ReportGenerator._cmdline_meta_html(cmdline)}
        </div>
    </div>
</div>

<div class="container">

{startup_banner_html}

<div class="summary-bar">
    <div class="summary-card"><div class="num">{m_total}</div><div class="label">总测试数</div></div>
    <div class="summary-card card-pass"><div class="num">{m_pass}</div><div class="label">通过</div></div>
    <div class="summary-card card-fail"><div class="num">{sum(1 for r in model_results if (not r.passed) and (not r.crashed) and (not r.skipped))}</div><div class="label">失败</div></div>
    <div class="summary-card card-ignored" title="服务端已知占位/未实现缺陷的 FAIL 子集"><div class="num">{sum(1 for r in model_results if (not r.passed) and (not r.crashed) and (not r.skipped) and getattr(r, 'ignorable', False))}</div><div class="label">可忽略</div></div>
    <div class="summary-card card-crash"><div class="num">{sum(1 for r in model_results if r.crashed)}</div><div class="label">崩溃</div></div>
    <div class="summary-card"><div class="num">{sum(1 for r in model_results if r.skipped)}</div><div class="label">跳过</div></div>
    <div class="summary-card card-capability" title="根因判定为模型自身能力/输出质量局限而非服务端缺陷的诊断性标注;诊断性维度,不改变 passed/failed/退出码判定"><div class="num">{sum(1 for r in model_results if getattr(r, 'model_capability_issue', False))}</div><div class="label">模型能力问题</div></div>
</div>

<div class="progress-bar">
    <div class="progress-fill {'good' if m_rate >= 80 else ('warn' if m_rate >= 50 else 'bad')}" style="width:{max(m_rate, 5):.0f}%">
        <span class="progress-text">通过率 {m_rate:.1f}%</span>
    </div>
</div>
<div class="progress-meta"><span>模型通过率</span><span class="pct">{m_rate:.1f}%</span></div>

<div class="section">
<h2><span class="icon">&#9889;</span> 模型推理性能</h2>
<div class="model-section">
    <div class="group-section">
        {perf_table}
    </div>
</div>
</div>

<div class="section">
<h2><span class="icon">&#128737;</span> 服务功能接口</h2>
<div class="model-section">
    <div class="group-section">
        {service_table}
    </div>
</div>
</div>

{f'''<div class="section">
<h2><span class="icon">&#128295;</span> 其它/专项测试</h2>
<div class="model-section">
    <div class="group-section">
        {leftover_table}
    </div>
</div>
</div>''' if leftover_table else ""}
{model_builder_html}
{model_sampleapp_html}
{model_toolcalls_html}

{perf_report_html}
{crash_html}

<div class="footer">
    {_html_escape(model)} Test Report &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}
</div>

</div>
</body>
</html>"""

            ReportGenerator._assert_no_placeholder_leak(html, f"模型报告 report_{model}.html")
            safe_model_name = model.replace(" ", "_").replace("/", "_")
            out_path = Path(out_dir) / f"report_{safe_model_name}.html"
            with open(out_path, "w", encoding="utf-8") as f:
                f.write(html)
            print(f"[输出] 模型报告: {out_path}")

    @staticmethod
    def generate_html(all_results, perf_data, crash_events, out_dir, remote_mode=False):
        """向后兼容：调用 generate_summary_html + generate_model_reports"""
        ReportGenerator.generate_summary_html(all_results, perf_data, crash_events, out_dir, remote_mode)
        ReportGenerator.generate_model_reports(all_results, perf_data, crash_events, out_dir, remote_mode)

    @staticmethod
    def generate_conversations(all_results, out_dir):
        """生成详细数据记录 HTML — 包含 chat 对话、textsplitter、fetch 等大数据量接口的完整响应"""
        # 收集所有需要详细展示的结果。tool_calls 测试(即使名称含"chat/completions"子串)排除在外：
        # 它们与同一轮真正的 chat 测试共用相同的 model_R{round}_{mode} 锚点会互相冲突，且核心诊断
        # 价值(工具调用结构/流式重建参数)已下沉到独立的 report_tool_calls.html。
        chat_results = [r for r in all_results
                        if "chat/completions" in r.name and not r.name.startswith("POST /v1/chat/completions (tool_call")]
        textsplitter_results = [r for r in all_results if "textsplitter" in r.name and r.response_data]
        fetch_results = [r for r in all_results if r.name == "POST /fetch" and r.response_data]

        if not chat_results and not textsplitter_results and not fetch_results:
            return

        now_str = datetime.now().strftime('%Y-%m-%d %H:%M:%S')
        stream_count = sum(1 for r in chat_results if r.is_stream)
        non_stream_count = len(chat_results) - stream_count
        format_counts = {}
        for r in chat_results:
            fmt = getattr(r, "request_format", "") or "openai_string"
            format_counts[fmt] = format_counts.get(fmt, 0) + 1

        # ---- Chat 对话卡片 ----
        chat_cards_html = ""
        for r in chat_results:
            mode = "stream" if r.is_stream else "nonstream"
            anchor_id = f"{r.model_name}_R{r.round_num}_{mode}"
            mode_label = "Stream" if r.is_stream else "Non-Stream"
            mode_class = "mode-stream" if r.is_stream else "mode-nonstream"
            stream_info = ""
            if r.is_stream and r.chunk_count > 0:
                stream_info = f"""<div class="stream-metrics">
                    <span><strong>Chunks:</strong> {r.chunk_count}</span>
                    <span><strong>TTFT:</strong> {r.ttft_ms:.0f}ms</span>
                    <span><strong>总耗时:</strong> {r.latency_ms:.0f}ms</span>
                </div>"""
            elif not r.is_stream:
                stream_info = f"""<div class="stream-metrics">
                    <span><strong>响应延迟:</strong> {r.latency_ms:.0f}ms</span>
                </div>"""
            status_class = "badge-pass" if r.passed else ("badge-crash" if r.crashed else "badge-fail")
            status_text = "PASS" if r.passed else ("CRASH" if r.crashed else "FAIL")
            fmt_badge = _content_format_badge_html(r)
            # 多模态用例(client-style/openai-style 图片/音频)在 media_image_data_uri/
            # media_audio_data_uri 里带着可直接渲染的 data URI —— 这里把真正传给模型的
            # 图片/音频素材原样展示在 USER 消息下方，而不是只有一句"该模型支持图片"这类
            # 文字描述、看不到到底传了哪张图/哪段音频。
            media_html = ""
            if getattr(r, "media_image_data_uri", ""):
                media_html += (f'<div class="msg-media"><img src="{r.media_image_data_uri}" alt="multimodal input image">'
                               f'<div class="msg-media-label">{_html_escape(r.media_asset_label)}</div></div>')
            if getattr(r, "media_audio_data_uri", ""):
                media_html += (f'<div class="msg-media"><audio controls src="{r.media_audio_data_uri}"></audio>'
                               f'<div class="msg-media-label">{_html_escape(r.media_asset_label)}</div></div>')
            chat_cards_html += f"""
            <div class="conv-card" id="{_html_escape(anchor_id)}">
                <div class="conv-meta">
                    <span class="badge {mode_class}">{mode_label}</span>{fmt_badge}
                    <span class="badge {status_class}">{status_text}</span>
                    <span class="model-tag">{_html_escape(r.model_name)}</span>
                    <span class="round-tag">Round {r.round_num}</span>
                </div>
                <div class="message user-msg">
                    <div class="msg-role">USER</div>
                    <div class="msg-content">{_html_escape(r.text_prompt)}</div>
                    {media_html}
                </div>
                <div class="message assistant-msg">
                    <div class="msg-role">ASSISTANT</div>
                    <div class="msg-content">{_html_escape(r.text_response) if r.text_response else '(无响应)'}</div>
                </div>
                {stream_info}
            </div>"""

        # ---- Textsplitter 卡片 ----
        textsplitter_cards_html = ""
        for r in textsplitter_results:
            anchor_id = f"{r.model_name}_R{r.round_num}_textsplitter"
            status_class = "badge-pass" if r.passed else ("badge-crash" if r.crashed else "badge-fail")
            status_text = "PASS" if r.passed else ("CRASH" if r.crashed else "FAIL")
            data = r.response_data or {}
            seg_count = data.get("segment_count", 0)
            segments = data.get("segments", [])
            seg_html = ""
            for i, seg in enumerate(segments):
                seg_text = seg.get("text", "")
                seg_len = seg.get("length", len(seg_text))
                seg_html += f'<div class="seg-item"><span class="seg-idx">#{i+1}</span> <span class="seg-len">[{seg_len} chars]</span> {_html_escape(seg_text)}</div>'
            textsplitter_cards_html += f"""
            <div class="conv-card" id="{_html_escape(anchor_id)}">
                <div class="conv-meta">
                    <span class="badge mode-textsplitter">TextSplitter</span>
                    <span class="badge {status_class}">{status_text}</span>
                    <span class="model-tag">{_html_escape(r.model_name)}</span>
                    <span class="round-tag">Round {r.round_num}</span>
                    <span class="round-tag">{seg_count} segments</span>
                </div>
                <div class="data-content">{seg_html if seg_html else '<em>无分段数据</em>'}</div>
            </div>"""

        # ---- Fetch 卡片 ----
        fetch_cards_html = ""
        for r in fetch_results:
            anchor_id = f"{r.model_name}_R{r.round_num}_fetch"
            status_class = "badge-pass" if r.passed else ("badge-crash" if r.crashed else "badge-fail")
            status_text = "PASS" if r.passed else ("CRASH" if r.crashed else "FAIL")
            data = r.response_data or {}
            history_count = data.get("history_count", 0)
            history = data.get("history", [])
            hist_html = ""
            for h in history:
                role = h.get("role", "unknown")
                content = h.get("content", "")
                role_cls = "user-msg" if role == "user" else "assistant-msg"
                hist_html += f"""<div class="message {role_cls}">
                    <div class="msg-role">{_html_escape(role.upper())}</div>
                    <div class="msg-content">{_html_escape(content)}</div>
                </div>"""
            fetch_cards_html += f"""
            <div class="conv-card" id="{_html_escape(anchor_id)}">
                <div class="conv-meta">
                    <span class="badge mode-fetch">Fetch History</span>
                    <span class="badge {status_class}">{status_text}</span>
                    <span class="model-tag">{_html_escape(r.model_name)}</span>
                    <span class="round-tag">Round {r.round_num}</span>
                    <span class="round-tag">{history_count} 条记录</span>
                </div>
                <div class="hist-content">{hist_html if hist_html else '<div class="data-content"><em>无历史数据</em></div>'}</div>
            </div>"""

        # ---- 组合各区域 ----
        sections_html = ""
        if chat_cards_html:
            sections_html += f"""<h2 class="section-title">💬 对话记录（Chat Completions）</h2>{chat_cards_html}"""
        if textsplitter_cards_html:
            sections_html += f"""<h2 class="section-title">✂️ 文本切分（TextSplitter）</h2>{textsplitter_cards_html}"""
        if fetch_cards_html:
            sections_html += f"""<h2 class="section-title">📜 对话历史（Fetch）</h2>{fetch_cards_html}"""

        html = f"""<!DOCTYPE html>
<html lang="zh-CN">
<head>
<meta charset="UTF-8">
<meta name="viewport" content="width=device-width, initial-scale=1.0">
<title>GenieAPIService 详细数据记录 - {now_str}</title>
<style>
:root {{
    --primary: #1565C0;
    --success: #2E7D32;
    --danger: #C62828;
    --warning: #E65100;
    --bg: #F5F7FA;
    --card-bg: #FFFFFF;
    --border: #E0E0E0;
    --text: #263238;
    --text-secondary: #546E7A;
    --user-bg: #E3F2FD;
    --assistant-bg: #F1F8E9;
    --radius: 10px;
}}
* {{ margin: 0; padding: 0; box-sizing: border-box; }}
body {{ font-family: -apple-system, BlinkMacSystemFont, 'Segoe UI', 'PingFang SC', 'Microsoft YaHei', sans-serif;
       background: var(--bg); color: var(--text); line-height: 1.6; }}
.page-header {{ background: linear-gradient(135deg, #1565C0 0%, #0D47A1 100%); color: white; padding: 35px 0; margin-bottom: 30px; }}
.page-header-inner {{ max-width: 900px; margin: 0 auto; padding: 0 30px; }}
.page-header h1 {{ font-size: 24px; font-weight: 600; margin-bottom: 6px; }}
.page-header .info {{ opacity: 0.85; font-size: 13px; display: flex; gap: 20px; flex-wrap: wrap; margin-top: 10px; }}
.container {{ max-width: 900px; margin: 0 auto; padding: 0 30px 60px; }}
.section-title {{ font-size: 18px; font-weight: 600; color: var(--primary); margin: 30px 0 16px; padding-bottom: 8px; border-bottom: 2px solid var(--primary); }}
.conv-card {{ background: var(--card-bg); border-radius: var(--radius); margin-bottom: 20px; box-shadow: 0 2px 8px rgba(0,0,0,0.06); overflow: hidden; }}
.conv-meta {{ display: flex; gap: 10px; align-items: center; padding: 12px 20px; background: #FAFAFA; border-bottom: 1px solid var(--border); flex-wrap: wrap; }}
.badge {{ font-size: 11px; font-weight: 600; padding: 3px 10px; border-radius: 12px; text-transform: uppercase; letter-spacing: 0.5px; }}
.mode-stream {{ background: #E8F5E9; color: #2E7D32; }}
.mode-nonstream {{ background: #E3F2FD; color: #1565C0; }}
.mode-textsplitter {{ background: #FFF3E0; color: #E65100; }}
.mode-fetch {{ background: #F3E5F5; color: #6A1B9A; }}
.badge-pass {{ background: #E8F5E9; color: #2E7D32; }}
.badge-fail {{ background: #FFEBEE; color: #C62828; }}
.badge-crash {{ background: #FFF3E0; color: #E65100; }}
.model-tag {{ font-size: 12px; color: var(--primary); font-weight: 600; }}
.round-tag {{ font-size: 12px; color: var(--text-secondary); }}
.message {{ padding: 16px 20px; }}
.user-msg {{ background: var(--user-bg); border-left: 4px solid #1976D2; }}
.assistant-msg {{ background: var(--assistant-bg); border-left: 4px solid #43A047; }}
.msg-role {{ font-size: 11px; font-weight: 700; text-transform: uppercase; letter-spacing: 1px; margin-bottom: 6px; color: var(--text-secondary); }}
.msg-content {{ font-size: 14px; line-height: 1.7; white-space: pre-wrap; word-wrap: break-word; max-height: 500px; overflow-y: auto; }}
.msg-media {{ margin-top: 10px; }}
.msg-media img {{ max-width: 320px; max-height: 320px; border-radius: var(--radius-sm, 4px); border: 1px solid var(--border); display: block; }}
.msg-media audio {{ width: 320px; }}
.msg-media-label {{ font-size: 11px; color: var(--text-secondary); margin-top: 4px; font-family: var(--font-mono, monospace); }}
.stream-metrics {{ display: flex; gap: 20px; padding: 10px 20px; background: #FAFAFA; border-top: 1px solid var(--border); font-size: 12px; color: var(--text-secondary); }}
.data-content {{ padding: 16px 20px; font-size: 13px; line-height: 1.6; max-height: 600px; overflow-y: auto; }}
.hist-content {{ max-height: 800px; overflow-y: auto; }}
.seg-item {{ padding: 8px 12px; border-bottom: 1px solid var(--border); font-size: 13px; line-height: 1.5; }}
.seg-item:last-child {{ border-bottom: none; }}
.seg-idx {{ font-weight: 700; color: var(--primary); margin-right: 8px; }}
.seg-len {{ font-size: 11px; color: var(--text-secondary); margin-right: 8px; }}
.footer {{ text-align: center; padding: 30px; color: var(--text-secondary); font-size: 12px; border-top: 1px solid var(--border); margin-top: 20px; }}
</style>
</head>
<body>
<div class="page-header">
    <div class="page-header-inner">
        <h1>GenieAPIService 详细数据记录</h1>
        <div class="info">
            <span><strong>生成时间:</strong> {now_str}</span>
            <span><strong>对话:</strong> {len(chat_results)} ({stream_count} stream / {non_stream_count} non-stream)</span>
            <span><strong>请求格式:</strong> {format_counts.get("openai_string", 0)} 字符串 / {format_counts.get("openai_array", 0)} 数组 / {format_counts.get("client_object", 0)} 对象</span>
            <span><strong>TextSplitter:</strong> {len(textsplitter_results)}</span>
            <span><strong>Fetch:</strong> {len(fetch_results)}</span>
            <span><a href="report.html" style="color:white; text-decoration:underline;">← 返回总汇报</a></span>
        </div>
    </div>
</div>
<div class="container">
{sections_html}
<div class="footer">GenieAPIService Data Log &middot; <a href="report.html">返回总汇报</a> &middot; {now_str}</div>
</div>
</body>
</html>"""

        out_path = Path(out_dir) / "conversations.html"
        with open(out_path, "w", encoding="utf-8") as f:
            f.write(html)
        print(f"[输出] 详细数据记录: {out_path}")


def _html_escape(text):
    """简单的 HTML 转义"""
    if not text:
        return ""
    return (str(text)
            .replace("&", "&amp;")
            .replace("<", "&lt;")
            .replace(">", "&gt;")
            .replace('"', "&quot;"))


def _crash_badge_html(c):
    """根据 CrashEvent 的 endpoint/detail 判断是否为 MNN OOM 相关事件,返回对应徽章 HTML；
    不相关时返回空字符串。真实 OOM(MNN_OOM_CRASH)与疑似级联崩溃(MNN_OOM_CASCADE)使用不同样式,
    避免阅读者把"MNN 自身真实问题"和"疑似被 MNN OOM 拖累而崩溃的其它后端"混为一谈；两者
    都是需要关注的真实问题、都已计入 failed/crashed 统计,徽章仅作诊断提示,不代表已豁免。"""
    endpoint = c.endpoint or ""
    detail_lower = (c.detail or "").lower()
    if endpoint == "MNN_OOM_CASCADE" or "mnn_oom_cascade" in detail_lower:
        return '<span class="badge-mnn-cascade" title="疑似因同进程内 MNN 模型 OOM 拖垮进程而级联崩溃,需人工排查根因;已计入真实失败,不代表豁免">疑似级联崩溃(非豁免)</span>'
    if endpoint == "MNN_OOM_CRASH":
        return '<span class="badge-mnn-oom" title="MNN 模型自身触发的真实内存不足/崩溃事件">MNN真实OOM</span>'
    return ""


# ============================================================================
# MultiModelTester - 多后端顺序切换加载与路由测试
# ============================================================================
class MultiModelTester:
    """
    阶段 3：多后端顺序切换加载与路由测试。

    本仓库已删除并发多模型托管设计（原 loaded_models_ 注册表），运行时只有一个当前活跃
    模型；本阶段验证的是 ModelManager::LoadModelByName() 的顺序单模型切换能力在
    QNN(NPU)/GGUF(GPU)/MNN(CPU) 三种后端间都能正常工作，不要求多模型同时驻留：
    1. GET /models 返回当前已加载的模型
    2. 依次向 npu/gpu/cpu 三种后端的模型发送 chat 请求，验证顺序切换均成功
    3. 并发向同一/不同模型发送请求，验证并发安全性（需要 ≥2 个已加载模型才有意义，
       单模型架构下天然多为 skipped）
    4. 请求未加载/不存在的模型时返回 404
    5. MNN 模型加载失败（含崩溃）标记为 ignorable

    内存约束说明：
    - QNN/NPU 模型加载失败时 LoadModel 返回 false，服务继续运行
    - GGUF/GPU 模型 OOM 时抛出异常，被捕获后跳过该模型
    - MNN/CPU 模型 OOM 时可能导致进程崩溃，测试框架检测崩溃并标记 ignorable
    """

    # MNN 后端标识（加载失败/崩溃时标记为 ignorable）
    MNN_BACKENDS = {"mnn"}

    @staticmethod
    def _infer_device(model_name):
        """根据模型目录名猜测其后端/设备：GGUF→gpu，MNN→cpu，其余（QNN）→npu"""
        return infer_backend(model_name)[1]

    def __init__(self, host, port, svc, perf, round_num=1):
        self.base_url = f"http://{host}:{port}"
        self.svc = svc
        self.perf = perf
        self.round_num = round_num
        self.results: list[TestResult] = []
        self.crash_events: list[CrashEvent] = []
        self._restart_count = 0
        self.MAX_RESTARTS = 3
        # _get/_post 失败时(返回 None)把真实异常类型+消息记录在这里,供调用方在 detail 里
        # 附带具体原因，便于区分究竟是 ConnectionError 还是 ReadTimeout。
        self._last_request_error = ""

    # ── 内部辅助 ──────────────────────────────────────────────────────────────

    def _get(self, path, timeout=15):
        try:
            r = requests.get(f"{self.base_url}{path}", timeout=timeout)
            self._last_request_error = ""
            return r
        except Exception as e:
            self._last_request_error = f"{type(e).__name__}: {e}"
            return None

    def _post(self, path, body, timeout=300):
        try:
            r = requests.post(f"{self.base_url}{path}", json=body, timeout=timeout)
            self._last_request_error = ""
            return r
        except Exception as e:
            self._last_request_error = f"{type(e).__name__}: {e}"
            return None

    def _make_result(self, name, passed, status_code, detail, ignorable=False, ignore_reason="",
                      skipped=False, crashed=False):
        return TestResult(
            name=name, round_num=self.round_num, model_name="_multi_model_",
            passed=passed, status_code=status_code, latency_ms=0,
            detail=detail, ignorable=ignorable, ignore_reason=ignore_reason,
            skipped=skipped, crashed=crashed
        )

    # ── 测试用例 ──────────────────────────────────────────────────────────────

    def test_models_list(self):
        """验证 GET /models 返回多模型列表（至少 1 个模型）"""
        name = "MULTI: GET /models (multi-model list)"
        r = self._get("/models")
        if r is None:
            return self._make_result(name, False, 0, "请求失败（连接错误）")
        if r.status_code != 200:
            return self._make_result(name, False, r.status_code, f"status={r.status_code}")
        try:
            data = r.json()
            model_list = data.get("data", [])
            loaded_entries = []
            for m in model_list:
                if not m.get("is_loaded"):
                    continue
                loaded_entries.append({
                    "id": m.get("id", ""),
                    "backend": m.get("backend", ""),
                    "device": m.get("device", ""),
                    "context_length": m.get("context_length", ""),
                })
            names = [m.get("id", "?") for m in loaded_entries]
            if len(names) == 0:
                return self._make_result(name, False, 200, "模型列表为空（无模型加载成功）")
            type_summary = sorted({f"{m.get('backend')}/{m.get('device')}" for m in loaded_entries})
            # 额外校验每条记录的 backend/device 字段是否落在预期取值集合内——如果服务端把
            # 这两个字段返回为空字符串或拼错了取值，仅判断列表非空无法发现，这里补一道
            # 最小成本的取值校验，命中即降级为失败。
            _valid_backends = {"qnn", "mnn", "gguf"}
            _valid_devices = {"npu", "cpu", "gpu"}
            bad_entries = [m for m in loaded_entries
                           if str(m.get("backend", "")).lower() not in _valid_backends
                           or str(m.get("device", "")).lower() not in _valid_devices]
            if bad_entries:
                detail = (f"已加载 {len(names)} 个模型: {names}; 类型: {type_summary}; "
                          f"发现 backend/device 字段异常的条目: {bad_entries}")
                result = self._make_result(name, False, 200, detail)
                result.response_data = {"loaded_models": loaded_entries, "type_summary": type_summary}
                return result
            detail = f"已加载 {len(names)} 个模型: {names}; 类型: {type_summary}"
            result = self._make_result(name, True, 200, detail)
            result.response_data = {"loaded_models": loaded_entries, "type_summary": type_summary}
            return result
        except Exception as e:
            return self._make_result(name, False, r.status_code, f"JSON 解析失败: {e}")

    def _get_loaded_model_entries(self):
        """从 /models 获取当前**已加载**模型的结构化条目。"""
        r = self._get("/models")
        if r is None or r.status_code != 200:
            return []
        try:
            data = r.json()
            entries = []
            for m in data.get("data", []):
                if not (m.get("id") and m.get("is_loaded")):
                    continue
                entries.append({
                    "id": m.get("id", ""),
                    "backend": m.get("backend", ""),
                    "device": m.get("device", ""),
                    "context_length": m.get("context_length", ""),
                })
            return entries
        except Exception:
            return []

    def _get_loaded_models(self):
        """从 /models 获取当前**已加载**的模型名称列表。

        注意：/models 接口会返回磁盘扫描到的全部模型（含 is_loaded=False 的未加载模型，
        用于展示可切换的候选列表），必须按 is_loaded 字段过滤，否则会把未加载的模型
        误当作"已加载"，导致后续路由测试/并发测试对未加载模型发起请求，
        触发意外的动态切换（尤其是 NPU 设备的连续/并发切换可能引发竞态崩溃）。
        """
        return [m.get("id", "") for m in self._get_loaded_model_entries() if m.get("id")]

    def _get_service_config_models(self):
        """从 /profile 或 /models 获取 service_config.json 中配置的所有模型（含未加载的）"""
        # 通过 /models 只能获取已加载的；service_config 中的全量列表需要从别处获取
        # 这里直接返回已加载列表，未加载的模型通过 404 测试覆盖
        return self._get_loaded_models()

    def ensure_multi_backend_loaded(self, models_by_device):
        """依次向 npu/gpu(GGUF)/cpu(MNN) 三个不同设备的模型发送 chat 请求，触发
        chat_request_handler.cpp 中已有的"磁盘扫描 + 动态加载"分支（ModelManager::LoadModelByName()
        顺序单模型切换），验证三种后端各自都能被成功加载/切换到。

        本仓库已删除并发多模型托管设计（原 loaded_models_ 注册表），运行时只有一个当前活跃模型，
        因此不再要求三者"同时驻留"，只要求依次切换均成功——这与 ModelManager::LoadModelByName()
        的顺序切换语义（先卸载旧模型再加载新模型）完全一致。

        models_by_device: dict[str, str]，形如 {"npu": "qwen3-8b-8480", "gpu": "gpt-oss-20b-GGUF", "cpu": "gpt-oss-20b-MNN"}
        返回一条汇总 TestResult：MNN OOM 崩溃时按现有 ignorable 机制处理并跳过继续；因更早设备
        崩溃导致循环提前结束、从未被真正请求过的设备标记为 skipped（而不是失败）。
        """
        name = "MULTI: sequential backend switching (npu/gpu/cpu each independently loadable)"
        touched = []
        device_results = {}
        for device, model_name in models_by_device.items():
            is_mnn = device == "cpu"
            r = self.test_route_to_model(model_name)
            device_results[device] = r
            self.results.append(r)
            touched.append(f"{device}:{model_name}→{'OK' if r.passed else ('SKIP' if r.skipped else ('IGN' if r.ignorable else 'FAIL'))}")
            if r.crashed:
                if is_mnn and self._restart_count < self.MAX_RESTARTS:
                    # MNN OOM 崩溃(分类A)：自动重启并跳过该模型，继续尝试后续设备
                    self._restart_count += 1
                    # 必须在 restart() 之前捕获日志尾部/退出码,否则拿到的是重启后新进程的信息,
                    # 而不是真正崩溃的那个进程的证据。
                    log_tail = _capture_log_tail(self.svc)
                    restarted = self.svc.restart()
                    self.crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=model_name, round_num=self.round_num,
                        endpoint="MNN_OOM_CRASH",
                        detail=f"MNN OOM 崩溃后已自动重启(第{self._restart_count}次): {'成功' if restarted else '失败'}",
                        log_tail=log_tail
                    ))
                    self.results.append(TestResult(
                        name=f"MULTI: auto-restart after MNN OOM ({model_name})",
                        round_num=self.round_num, model_name="_multi_model_",
                        passed=restarted, status_code=0, latency_ms=0,
                        detail="MNN OOM 崩溃后已自动重启,跳过该模型继续后续设备" if restarted else "重启失败,不可恢复",
                        ignorable=restarted, ignore_reason="MNN OOM 崩溃后已自动重启并跳过" if restarted else "",
                        auto_restarted=restarted
                    ))
                # 无论是 MNN 自身崩溃还是其它真实错误,进程已不可用,不再继续尝试后续设备
                break

        skipped_devices = [d for d in models_by_device.keys() if d not in device_results]
        bad_devices = [d for d, r in device_results.items()
                       if (not r.passed) and (not r.skipped) and (not r.ignorable)]
        detail = (f"顺序切换结果: {touched}"
                  + (f", 因更早设备崩溃未被真正尝试: {sorted(skipped_devices)}" if skipped_devices else ""))
        if bad_devices:
            # 至少一个设备被真正请求过但切换/加载失败(且非崩溃/优雅跳过/已知 ignorable)——
            # 这是需要关注的真实问题。
            result = self._make_result(name, False, 0, detail)
        elif skipped_devices:
            # 有设备从未被真正尝试(更早设备崩溃导致循环提前 break)，无法验证该设备是否可
            # 正常切换加载，精确标记为 skipped=True，而不是失败。
            result = self._make_result(
                name, False, 0, detail, skipped=True,
                ignore_reason=f"更早的设备崩溃导致循环提前结束,{sorted(skipped_devices)} 后端从未被真正请求"
            )
        else:
            result = self._make_result(name, True, 0, detail)
        result.response_data = {
            "device_results": {d: {"passed": r.passed, "skipped": r.skipped, "ignorable": r.ignorable}
                                for d, r in device_results.items()},
            "skipped_devices": sorted(skipped_devices),
            "request_order": touched,
        }
        return result

    def test_route_to_model(self, model_name):
        """向指定模型发送 chat 请求，验证路由正确性。

        失败/崩溃归类规则见 `_classify_process_down`。
        """
        name = f"MULTI: chat route → {model_name}"
        is_mnn = infer_backend(model_name)[0] == "mnn"
        body = {
            "model": model_name,
            "messages": [
                {"role": "user", "content": "Reply with one word: hello"}
            ],
            "stream": False,
            "max_tokens": 32
        }
        start = time.time()
        r = self._post("/v1/chat/completions", body, timeout=120)
        latency = (time.time() - start) * 1000

        if r is None:
            if _confirm_process_dead(self.svc):
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, model_name)
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(),
                    model_name=model_name, round_num=self.round_num,
                    endpoint="MNN_OOM_CRASH" if is_mnn else ("MNN_OOM_CASCADE" if ignore_reason == "mnn_oom_cascade" else "SERVICE_CRASH"),
                    detail=f"{name}: 连接失败,服务进程已退出; {classify_detail}",
                    log_tail=_capture_log_tail(self.svc)
                ))
                return TestResult(
                    name=name, round_num=self.round_num, model_name="_multi_model_",
                    passed=False, status_code=0, latency_ms=latency,
                    detail=classify_detail,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    crashed=True
                )
            # 进程仍存活,只是这次请求本身连接失败/超时: 该模型自身的真实问题,不做豁免
            return TestResult(
                name=name, round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=latency,
                detail=f"请求失败（{self._last_request_error or '连接错误/超时'},进程仍存活,应视为该模型自身的真实问题）"
            )

        if r.status_code == 200:
            try:
                data = r.json()
                choices = data.get("choices", [])
                if choices and "message" in choices[0]:
                    content = choices[0]["message"].get("content", "")
                    return TestResult(
                        name=name, round_num=self.round_num, model_name="_multi_model_",
                        passed=len(content) > 0, status_code=200, latency_ms=latency,
                        detail=f"OK response_len={len(content)}"
                    )
                return self._make_result(name, False, 200, "缺少 choices[0].message.content")
            except Exception as e:
                return self._make_result(name, False, 200, f"JSON 解析失败: {e}")

        if r.status_code == 500:
            failure_reason, failure_detail = _extract_failure_reason(r)
            if failure_reason == "insufficient_memory" and is_mnn:
                # 服务端优雅拒绝(MNN 内存预检查): 环境资源约束,不是代码缺陷,计为 skipped
                # 而非 failed,仍记录 MNN OOM 诊断标记供其它模型的级联判定参考。
                detail = f"服务端预判内存不足拒绝加载(failure_reason=insufficient_memory): {failure_detail}"
                _mark_mnn_oom(self.svc, model_name, detail)
                result = self._make_result(name, False, 500, detail, skipped=True)
                result.response_data = {"failure_reason": failure_reason, "failure_detail": failure_detail}
                return result

        if r.status_code in (404, 503):
            detail = f"status={r.status_code} 模型未加载（可能因内存不足被跳过）"
            if is_mnn:
                # MNN 模型自身未能加载成功且无法确认具体原因: 保守起见仍按真实问题处理
                # (与上面 500+insufficient_memory 的精确判定不同,这里状态码本身不携带
                # failure_reason,无法确认一定是内存不足)。
                classify_detail = f"MNN 模型自身未能加载成功,这是需要关注的真实问题: {detail}"
                _mark_mnn_oom(self.svc, model_name, classify_detail)
                return TestResult(
                    name=name, round_num=self.round_num, model_name="_multi_model_",
                    passed=False, status_code=r.status_code, latency_ms=latency,
                    detail=classify_detail
                )
            oom_event = _get_mnn_oom_event(self.svc)
            if oom_event:
                # 疑似同进程内此前已发生 MNN OOM，该模型可能因资源被占用而未能加载；但这只是
                # 诊断性提示，不代表豁免——404/503 且进程仍存活是"正常的优雅失败"，本来就不该
                # 造成连坐，如实计入该模型自身的真实失败。
                classify_detail = (f"疑似因同进程内 MNN 模型({oom_event['model_name']})此前发生 OOM,"
                                    f"该模型可能因资源被占用而未能加载(仅诊断提示,不代表豁免): {detail} "
                                    f"(ignore_reason=mnn_oom_cascade)")
                return TestResult(
                    name=name, round_num=self.round_num, model_name="_multi_model_",
                    passed=False, status_code=r.status_code, latency_ms=latency,
                    detail=classify_detail,
                    ignorable=False, ignore_reason="mnn_oom_cascade"
                )
            return TestResult(
                name=name, round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=r.status_code, latency_ms=latency,
                detail=f"{detail},应视为该模型自身的真实问题"
            )

        return self._make_result(name, False, r.status_code,
                                 f"status={r.status_code} body={r.text[:120]}")

    def test_unknown_model_route(self):
        """请求不存在的模型，期望立即返回 404/400（延迟 <5s，防止 60×500ms 轮询等待式退化重现）。"""
        name = "MULTI: invalid model route returns 404/400"
        invalid_model = "__invalid_model_for_negative_route_test__"
        body = {
            "model": invalid_model,
            "messages": [{"role": "user", "content": "hello"}],
            "stream": False,
            "max_tokens": 8
        }
        start = time.time()
        r = self._post("/v1/chat/completions", body, timeout=30)
        latency_ms = (time.time() - start) * 1000
        if r is None:
            if _confirm_process_dead(self.svc):
                # invalid_model 不是真实模型,不可能是 MNN,只会落在"级联失败"或"真实错误"两支。
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, invalid_model)
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(),
                    model_name=invalid_model, round_num=self.round_num,
                    endpoint="MNN_OOM_CASCADE" if ignore_reason == "mnn_oom_cascade" else "SERVICE_CRASH",
                    detail=f"{name}: 连接失败,服务进程已退出; {classify_detail}",
                    log_tail=_capture_log_tail(self.svc)
                ))
                return TestResult(
                    name=name, round_num=self.round_num, model_name="_multi_model_",
                    passed=False, status_code=0, latency_ms=latency_ms,
                    detail=classify_detail,
                    ignorable=ignorable, ignore_reason=ignore_reason,
                    crashed=True,
                    response_data={"invalid_model": invalid_model}
                )
            return TestResult(
                name=name, round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=latency_ms,
                detail=f"请求失败（{self._last_request_error or '连接错误/超时'},进程仍存活）",
                response_data={"invalid_model": invalid_model}
            )
        # 5 秒的上限足够宽松以吸收正常调度抖动，同时能捕获任何重新引入"阻塞轮询"式退化。
        latency_ok = latency_ms < 5000
        passed = r.status_code in (404, 400) and latency_ok
        detail = f"status={r.status_code}, latency={latency_ms:.0f}ms" + (
            " (符合预期)" if passed else " (期望 404/400 且 <5000ms，用于防止 30 秒轮询等待式退化重现)")
        result = TestResult(
            name=name, round_num=self.round_num, model_name="_multi_model_",
            passed=passed, status_code=r.status_code, latency_ms=latency_ms,
            detail=detail
        )
        result.response_data = {"invalid_model": invalid_model}
        return result

    def test_concurrent_requests(self, loaded_models):
        """并发向不同模型发送请求，验证并发安全性"""
        name = "MULTI: concurrent requests to different models"
        if len(loaded_models) < 2:
            # 已加载模型 <2 个时,并发安全性根本没有被真正验证过,不能记为 passed=True——
            # 那样会扭曲报告语义,让人误以为"并发安全性已验证"。精确标记为 skipped=True。
            return self._make_result(
                name, False, 0,
                f"跳过（仅 {len(loaded_models)} 个模型加载成功，需要 ≥2 个才能测并发，未验证并发安全性）",
                skipped=True
            )

        from concurrent.futures import ThreadPoolExecutor, as_completed

        def send_request(model_name):
            body = {
                "model": model_name,
                "messages": [{"role": "user", "content": "Say hi"}],
                "stream": False,
                "max_tokens": 16
            }
            try:
                r = requests.post(f"{self.base_url}/v1/chat/completions",
                                  json=body, timeout=120)
                content = ""
                if r.status_code == 200:
                    try:
                        content = ((r.json().get("choices") or [{}])[0].get("message", {}) or {}).get("content", "") or ""
                    except Exception:
                        content = ""
                # 只有 200 且回复内容非空才视为真正成功——避免“全部 200 但回复都是空字符串”这类
                # “没真正验证任何东西却 100% 通过”的假衡量。
                return model_name, r.status_code, r.status_code == 200 and bool(content.strip())
            except Exception as e:
                return model_name, 0, False

        # 每个模型发一个并发请求
        results_map = {}
        with ThreadPoolExecutor(max_workers=len(loaded_models)) as executor:
            futures = {executor.submit(send_request, m): m for m in loaded_models}
            for future in as_completed(futures, timeout=180):
                try:
                    model_name, status, ok = future.result()
                    results_map[model_name] = (status, ok)
                except Exception as e:
                    model_name = futures[future]
                    results_map[model_name] = (0, False)

        passed_count = sum(1 for _, ok in results_map.values() if ok)
        detail_parts = [f"{m}→{s}" for m, (s, _) in results_map.items()]
        detail = f"{passed_count}/{len(loaded_models)} 成功: {', '.join(detail_parts)}"
        # 只要没有崩溃（status=0），并发测试就算通过（各模型独立，部分失败是正常的）
        no_crash = all(s != 0 for _, (s, _) in results_map.items())
        if not no_crash:
            all_crashed = all(s == 0 for _, (s, _) in results_map.items())
            # 崩溃永远是真实问题,不可豁免(ignorable 恒为 False)；ignore_reason 仅用于标注
            # 疑似与此前 MNN OOM 相关这一诊断信息,不再据此设置 ignorable=True。
            ignorable = False
            ignore_reason = ""
            classify_detail = ""
            if all_crashed:
                crashed_mnn_models = [m for m in loaded_models if infer_backend(m)[0] == "mnn"]
                if crashed_mnn_models:
                    classify_detail = (f"并发测试中服务进程崩溃,涉及 MNN 模型{crashed_mnn_models},"
                                        f"这是需要关注的真实OOM事件")
                    _mark_mnn_oom(self.svc, crashed_mnn_models[0], classify_detail)
                else:
                    oom_event = _get_mnn_oom_event(self.svc)
                    if oom_event:
                        classify_detail = (f"疑似因同进程内 MNN 模型({oom_event['model_name']})此前发生 OOM 导致进程退出"
                                            f"而级联崩溃,需人工排查根因;已计入真实失败,不代表豁免 (ignore_reason=mnn_oom_cascade)")
                        ignore_reason = "mnn_oom_cascade"
                    else:
                        classify_detail = "并发请求全部失败,且未检测到 MNN OOM 记录,应视为涉及模型自身的真实问题"
            detail_full = f"{detail}; {classify_detail}" if classify_detail else detail
            return TestResult(
                name=name, round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=0,
                detail=detail_full,
                ignorable=ignorable, ignore_reason=ignore_reason,
                crashed=all_crashed
            )
        return self._make_result(name, True, 200, detail)

    def test_default_model_routing(self):
        """向不带 model 字段的请求验证默认模型路由。

        背景（审计发现）：`ChatRequestHandler::ChatCompletions` 每次动态切换成功都会
        调用 `SetDefaultModel(modelName)`，把服务端的默认模型覆写为“最后一次被动态路由
        到的模型”，而不是固定为 `service_config.json` 里配置的那个；若该默认模型恰好在某个
        设备上被驱逐，`GetDefaultModel()` 会退化为 `unordered_map` 的任意元素。本测试不假定
        具体会路由到哪个模型（该行为目前是既定但不确定的实现细节，非本测试引入的新契约），
        只监控“不崩溃、不返回 5xx”这一条安全底线，作为回归预防线。"""
        name = "MULTI: default model route (no 'model' field) after dynamic switches"
        body = {
            "messages": [{"role": "user", "content": "Say hi"}],
            "stream": False,
            "max_tokens": 16
        }
        started = time.time()
        try:
            r = requests.post(f"{self.base_url}/v1/chat/completions", json=body, timeout=60)
        except Exception as e:
            latency = (time.time() - started) * 1000
            if _confirm_process_dead(self.svc):
                ignorable, ignore_reason, classify_detail = _classify_process_down(self.svc, "_multi_model_")
                self.crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(),
                    model_name="_multi_model_", round_num=self.round_num,
                    endpoint=name, detail=f"{type(e).__name__}: {e}; {classify_detail}",
                    log_tail=_capture_log_tail(self.svc)
                ))
                return TestResult(
                    name=name, round_num=self.round_num, model_name="_multi_model_",
                    passed=False, status_code=0, latency_ms=latency,
                    detail=f"请求异常: {type(e).__name__}: {e}; {classify_detail}",
                    crashed=True, ignorable=ignorable, ignore_reason=ignore_reason
                )
            # 进程仍存活,只是这次请求本身连接异常/超时: 不构成崩溃证据,与 test_route_to_model
            # 对同类异常的处理保持一致。
            return TestResult(
                name=name, round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=latency,
                detail=f"请求异常: {type(e).__name__}: {e}(进程仍存活,应视为该次请求自身的连接异常)"
            )
        latency_ms = (time.time() - started) * 1000
        passed = r.status_code == 200
        detail = (f"status={r.status_code}, latency={latency_ms:.0f}ms（不带 model 字段；当前实现里"
                  f"默认模型会随动态切换漂移，本检查只监控是否仍能正常响应，不校验具体路由到哪个模型）")
        return TestResult(
            name=name, round_num=self.round_num, model_name="_multi_model_",
            passed=passed, status_code=r.status_code, latency_ms=latency_ms,
            detail=detail
        )

    # ── 主入口 ────────────────────────────────────────────────────────────────

    def run_all(self, models_by_device=None, models_root=None, remote_mode=False):
        """执行所有多模型测试，返回 TestResult 列表

        models_by_device: 可选，形如 {"npu": ..., "gpu": ..., "cpu": ...}；
        长度 > 1 时先调用 ensure_multi_backend_loaded 主动触发多种设备的顺序切换加载
        （本仓库已删除并发多模型托管设计，运行时只有一个当前活跃模型，不再要求同时驻留）；
        长度 <=1（环境里只发现单一 backend 类型）时不再完全静默跳过、不留痕迹，而是
        登记一条 skipped=True 的 TestResult，明确说明"环境无法验证多后端切换"。

        models_root/remote_mode: 保留参数签名以兼容既有调用点（历史上用于驱动"两两同时
        驻留"降级验证，该验证已随并发多模型托管设计一起删除，此处不再使用）。
        """
        print(f"\n{'='*60}")
        print("阶段 3: 多后端顺序切换加载与路由测试")
        print(f"{'='*60}")

        if models_by_device and len(models_by_device) > 1:
            print(f"  验证 NPU/GGUF/MNN 三后端可依次切换加载 ... ", end="", flush=True)
            r = self.ensure_multi_backend_loaded(models_by_device)
            self.results.append(r)
            tag = "✓ PASS" if r.passed else ("⚠ SKIP" if r.skipped else ("⚠ IGN" if r.ignorable else "✗ FAIL"))
            print(f"{tag} ({r.detail[:100]})")
        elif models_by_device is not None:
            devices_found = sorted(models_by_device.keys())
            self.results.append(TestResult(
                name="MULTI: sequential backend switching (npu/gpu/cpu each independently loadable)",
                round_num=self.round_num, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=0,
                detail=f"环境中只发现单一后端类型({devices_found})，无法验证多后端切换",
                skipped=True
            ))

        # 1. 验证模型列表
        print("  测试 GET /models (multi-model list) ... ", end="", flush=True)
        r = self.test_models_list()
        self.results.append(r)
        print("✓ PASS" if r.passed else f"✗ FAIL ({r.detail})")

        # 2. 获取已加载模型列表
        loaded_models = self._get_loaded_models()
        print(f"  已加载模型: {loaded_models}")

        # 3. 对每个已加载模型测试路由
        for model_name in loaded_models:
            print(f"  测试路由 → {model_name} ... ", end="", flush=True)
            r = self.test_route_to_model(model_name)
            self.results.append(r)
            tag = "✓ PASS" if r.passed else ("⚠ SKIP" if r.skipped else ("⚠ IGN" if r.ignorable else "✗ FAIL"))
            print(f"{tag} ({r.detail[:60]})")

        # 4. 测试未知模型路由
        print("  测试无效模型路由 (expect 404/400) ... ", end="", flush=True)
        r = self.test_unknown_model_route()
        self.results.append(r)
        print("✓ PASS" if r.passed else ("⚠ SKIP" if r.skipped else f"✗ FAIL ({r.detail})"))

        # 4.5 不带 model 字段的默认路由回归监控（仅在确实发生过跨设备动态切换时才有意义；
        # 只监控"不崩溃/不返回 5xx"这条安全底线，不假定具体路由到哪个模型——见方法 docstring）。
        if models_by_device and len(models_by_device) > 1:
            print("  测试默认模型路由 (无 model 字段) ... ", end="", flush=True)
            r = self.test_default_model_routing()
            self.results.append(r)
            print("✓ PASS" if r.passed else ("⚠ SKIP" if r.skipped else f"✗ FAIL ({r.detail})"))

        # 5. 并发请求测试（需要 ≥2 个已加载模型）
        print("  测试并发请求 ... ", end="", flush=True)
        r = self.test_concurrent_requests(loaded_models)
        self.results.append(r)
        print("✓ PASS" if r.passed else ("⚠ SKIP" if r.skipped else f"✗ FAIL ({r.detail})"))

        return self.results


# ============================================================================
# 主流程
# ============================================================================

# 常见的模型权重文件后缀，用于 discover_models 里检测"看起来像模型但缺 config.json"这类
# 目录，避免它被完全静默地漏测——用户跑完整套回归后如果只看"全部已发现模型都通过了"，
# 很难察觉少了一个目录；这里不阻断执行，只打印告警提示，让问题至少可见。
_MODEL_WEIGHT_EXTENSIONS = {".bin", ".mnn", ".gguf", ".onnx", ".safetensors"}


def _estimate_model_dir_size_bytes(models_root, model_name):
    """递归汇总某个模型目录下全部文件大小之和，作为该模型内存占用的粗略代理指标——
    与服务端 MNN 自身内存预检查同一思路（用磁盘权重文件大小估算运行时内存需求）。
    仅用于测试脚本自己为"多类型同时加载"挑选每个设备的候选模型时做启发式排序，
    不影响服务端真实的内存预检查逻辑（那部分完全由 C++ 侧负责）。
    读取失败（目录不存在/权限问题）时返回正无穷，避免因无法估算而被误判为"最小"。"""
    total = 0
    try:
        for f in (Path(models_root) / model_name).rglob("*"):
            if f.is_file():
                try:
                    total += f.stat().st_size
                except OSError:
                    continue
    except OSError:
        return float("inf")
    return total if total > 0 else float("inf")


def discover_models(models_dir):
    """扫描 models 目录，返回包含 config.json 的子目录列表。
    对"看起来像模型（含常见权重文件后缀）但缺 config.json"的子目录打印告警,
    而不是完全静默跳过——否则用户很容易在不知情的情况下漏测一个模型。"""
    models_dir = Path(models_dir)
    if not models_dir.exists():
        print(f"ERROR: models 目录不存在: {models_dir}")
        sys.exit(1)
    models = []
    for d in sorted(models_dir.iterdir()):
        if not d.is_dir():
            continue
        if (d / "config.json").exists():
            models.append(d.name)
            continue
        try:
            looks_like_model = any(f.suffix.lower() in _MODEL_WEIGHT_EXTENSIONS
                                    for f in d.iterdir() if f.is_file())
        except OSError:
            looks_like_model = False
        if looks_like_model:
            print(f"WARNING: 目录 {d.name} 含权重文件但缺少 config.json，已跳过（未被纳入本次测试）")
    return models


def discover_models_remote(host, port):
    """从已运行的远程服务获取所有模型列表。
    对非 200 状态码、以及响应条目缺 "id" 字段的情况打印告警，而不是静默返回空列表/
    悄悄过滤掉——否则调用方无法区分"远程确实没有模型"和"接口请求异常但没报错"。"""
    url = f"http://{host}:{port}/models"
    try:
        r = requests.get(url, timeout=10)
        if r.status_code != 200:
            print(f"WARNING: {url} 返回非 200 状态码 {r.status_code}，视为无模型")
            return []
        data = r.json()
        models = data.get("data", [])
        missing_id = [m for m in models if isinstance(m, dict) and "id" not in m]
        if missing_id:
            print(f"WARNING: /models 响应中有 {len(missing_id)} 条记录缺少 'id' 字段，已忽略: {missing_id}")
        all_names = [m["id"] for m in models if isinstance(m, dict) and "id" in m]
        return all_names
    except Exception as e:
        print(f"ERROR: 无法从远程服务获取模型列表: {e}")
    return []


def _pick_builder_integration_model(models):
    preferred = [m for m in models if all(token not in m.lower() for token in ("gguf", "mnn", "gpu"))]
    return (preferred or models or [None])[0]


def _str2bool(v):
    """argparse 用的宽松 bool 解析：把 true/false/yes/no/1/0（大小写不敏感）转为 bool。"""
    if isinstance(v, bool):
        return v
    s = str(v).strip().lower()
    if s in ("true", "t", "yes", "y", "1", "on"):
        return True
    if s in ("false", "f", "no", "n", "0", "off"):
        return False
    raise argparse.ArgumentTypeError(f"无法解析为 bool: {v!r}")


# ============================================================================
# QAIModelBuilderLocalModelTester - 本地模型加载端到端验证
# ============================================================================
# 本次测试的被测对象是 GenieAPIService 本身（真实推理行为是否正确），Builder 只是启动/管理
# 它的载体。Builder 侧的 API 交互（配置根目录、注入模型、启动/停止、CSRF 握手）属于"手段
# 层"——只要能可靠地拿到一个正确运行的 GenieAPIService 实例即视为达标；验证重心放在"目标
# 层"：GenieAPIService 加载指定本地模型后，其真实推理行为（chat 回复内容非空且合理、后端
# 判定与目录名一致）是否正确可用。
#
# 硬约束：零侵入 Builder 源码——全部通过 Builder 已支持的官方接口达成：
#   * HTTP API (GET/POST /api/service/*)
#   * 环境变量 (QAI_AUTH__ENABLED、QAI_DATA__DATA_DIR，均由 QAIModelBuilderManager 设置)
#   * 纯文件系统操作 (mklink /J 目录联接——本地模型注入到 <data_dir>/models/<name>，
#     GenieAPIService 安装目录注入到 <data_dir>/bin/<name> 以触发官方自愈式安装发现；
#     Builder 完全无感知)。注意：POST /api/forge-config 对 genie_service.root_path 的写入
#     已核实不会被服务启动路径实际读取（见 configure_genie_root 文档字符串），本类不再使用它
#     来配置安装目录。
class ModelDirSnapshot:
    """进入 Builder 联动前对每个被 mklink /J 联接的模型目录拍一份关键小文件快照
    （仅 config.json/genie_config.json/.qai-install.json，不拷权重），退出时
    （含 finally 异常路径）逐一比对是否仍存在且字节相同；缺失或变化即视为
    不可忽略的 crashed 级别失败，绝不静默放过。

    背景：inject_local_models() 用 mklink /J 建立的是目录联接（junction），Windows 对联接
    路径的文件系统操作是透明穿透的——任何针对联接路径（Builder 侧 <data_dir>/models/<name>）
    的安装/更新/删除操作都会直接作用到联接指向的真实目录（--models/<name>）。如果测试过程
    中触发了任何一次这类路径，就会直接改写/删除真实模型目录下的配置文件而不留痕迹。本类只做
    最小侵入的"拍快照 -> 收尾比对"防护：只看几个关键小文件，缺失或内容变化即判定为不可忽略
    的失败，由调用方计入 crashed 级别的 TestResult。"""

    _WATCH_FILES = ("config.json", "genie_config.json", ".qai-install.json")

    def __init__(self):
        # model_dir(Path) -> {filename: sha256_hex_or_None}；None 表示快照时该文件不存在
        # （新出现的文件不列入校验范围，避免误报——见 verify() 的语义）。
        self._snapshots = {}

    @staticmethod
    def _hash_file(path):
        try:
            h = hashlib.sha256()
            with open(path, "rb") as f:
                for chunk in iter(lambda: f.read(65536), b""):
                    h.update(chunk)
            return h.hexdigest()
        except Exception:
            return None

    def snapshot(self, model_dirs):
        """对每个 model_dir 下 _WATCH_FILES 中存在的文件计算内容哈希并记录。
        model_dirs 应传入真实模型目录路径（--models/<name>），不是 Builder 侧的联接路径——
        联接对文件系统操作透明穿透，直接对源目录拍照语义等价，且不依赖联接是否仍然存在。"""
        for d in model_dirs:
            d = Path(d)
            files = {}
            for fname in self._WATCH_FILES:
                fp = d / fname
                files[fname] = self._hash_file(fp) if fp.is_file() else None
            self._snapshots[d] = files

    def verify(self):
        """返回违规描述字符串列表，空列表=通过。
        已快照且存在的文件：现在必须仍存在且哈希不变，否则记一条违规。
        已快照但当时不存在的文件：不做要求（新出现的文件不列入校验范围，避免误报）。"""
        violations = []
        for d, files in self._snapshots.items():
            for fname, old_hash in files.items():
                if old_hash is None:
                    continue  # 快照时不存在，不校验（避免对新出现的文件误报）
                fp = d / fname
                if not fp.is_file():
                    violations.append(
                        f"模型目录 {d} 下的 {fname} 已丢失（快照时存在，现在不存在）")
                    continue
                new_hash = self._hash_file(fp)
                if new_hash != old_hash:
                    violations.append(
                        f"模型目录 {d} 下的 {fname} 内容已变化（快照 sha256={old_hash}, "
                        f"当前 sha256={new_hash}）")
        return violations


class _BuilderLogProbe:
    """通过 Builder 官方 `GET /api/service/logs` SSE 接口做「本次请求新增日志」取证通道
    （Step6 新增，供场景 A/B/C 复用）。

    Builder 自己代理转发的聊天请求不经过我们直连测试时使用的本机日志文件路径——Builder 的
    `ProcessBackedInferenceService` 只把子进程 `GenieAPIService.exe` 的 stdout 读进内存 deque，
    不落盘文件——因此走 Builder 代理链路时 `_PromptLogProbe` 的「按文件字节偏移量增量读取」方式
    失效，必须换成这条 Builder 自带的 SSE 通道；`mark()`/`read_new()` 语义与 `_PromptLogProbe`
    对齐，只是用「先清空缓冲区」代替「记偏移量」（`GET /api/service/logs` 本身不支持按偏移量
    做增量读取，只能整体清空重来）。"""

    def __init__(self, csrf_session):
        self.csrf = csrf_session
        self._skip_from = 0
        self._tail_thread = None
        self._tail_lines = []
        self._tail_stop = None
        self._tail_resp = None

    def mark(self):
        """`POST /api/service/logs/clear`：清空 Builder 侧保留的 GenieAPIService stdout 缓冲区，
        之后 `read_new()` 读到的都是本次 `mark()` 之后新产生的日志，避免上一场景埋的 canary/
        `[Prompt]` 块污染下一场景的断言（同一个 Builder 代理子进程、同一份内存缓冲区）。"""
        try:
            r = self.csrf.post("/api/service/logs/clear", json={}, timeout=15)
            self._skip_from = int(r.json().get("skip_from", 0)) if r.status_code == 200 else 0
        except Exception:
            self._skip_from = 0

    def start_live_tail(self):
        """Step7 远程实测新增：与 `read_new()`（事后一次性抓取）不同，本方法在动作发起**之前**
        就开一个后台线程持续消费 `GET /api/service/logs` 的 SSE 流并逐行累积到内存列表。

        根因背景：`ProcessBackedInferenceService._log_buffer` 是 `deque(maxlen=6000)`（行数
        上限，非字符数），带图的多模态请求单次即可产生远超此深度的日志行——`IEmbedding::
        BuildPrompt()` 用 `My_Log(completed_prompt.c_str(), kInfo)` 把整份含 skill 目录/对话
        历史/System Prompt 的完整提示词当一次调用打印，其内部每个 `\n` 都会在 Python 侧
        `proc.stdout.readline()` 逐行读取时变成 deque 里独立的一"行"；只要这份提示词加上
        模型自身逐 token 生成日志的总行数超过 6000，`read_new()`（生成完全结束后才发起一次
        新连接抓取）读到的必然是"deque 已经回卷过的、只剩最新尾部"的残缺历史，早段（往往正是
        canary 所在处）已被回卷丢弃——这不是模型/取证正则的 bug，是"事后抓取"这种取证方式本身
        对深度有限的滚动缓冲区结构性不适配。改为"动作发起前就开始监听"从根本上规避这个问题：
        只要消费速度不明显慢于产生速度，我们自己在内存里攒的列表就不受 Builder 侧 deque 容量
        限制。"""
        self._tail_lines = []
        self._tail_stop = threading.Event()

        def _worker():
            resp = None
            try:
                resp = self.csrf.request(
                    "GET", "/api/service/logs", timeout=(10, 5), stream=True,
                    params={"skip": self._skip_from})
                self._tail_resp = resp
                if resp.status_code != 200:
                    return
                for raw in resp.iter_lines(decode_unicode=True):
                    if self._tail_stop.is_set():
                        break
                    if not raw or not raw.startswith("data:"):
                        continue
                    payload = raw[5:].strip()
                    if payload == "[DONE]":
                        break
                    try:
                        obj = json.loads(payload)
                    except Exception:
                        continue
                    if isinstance(obj, dict) and "line" in obj:
                        self._tail_lines.append(str(obj["line"]))
                    elif isinstance(obj, dict) and "error" in obj:
                        break
            except Exception:
                pass
            finally:
                if resp is not None:
                    try:
                        resp.close()
                    except Exception:
                        pass

        self._tail_thread = threading.Thread(target=_worker, daemon=True)
        self._tail_thread.start()
        # 给后台线程留出真正建立好 SSE 连接的时间，避免调用方紧接着发起的动作在
        # 连接就绪前就已经写日志，产生一段"抢跑"的取证盲区。
        time.sleep(0.5)

    def stop_live_tail(self, grace=5.0):
        """停止 `start_live_tail()` 开的后台监听线程并关闭连接，返回累积到的全部日志文本
        （用 `"\\n"` 拼接，与 `read_new()` 返回值同构，调用方可直接互换使用）。"""
        if self._tail_stop is not None:
            self._tail_stop.set()
        if self._tail_resp is not None:
            try:
                self._tail_resp.close()
            except Exception:
                pass
        if self._tail_thread is not None:
            self._tail_thread.join(timeout=grace)
        return "\n".join(self._tail_lines)

    def read_new(self, idle_timeout=10.0, total_timeout=30.0):
        """连接 `GET /api/service/logs?skip=<mark 时的 skip_from>`，收集新增行直到看到
        `[DONE]` 帧、空闲超时或总超时。返回拼接后的全部行文本（best-effort，连接/超时异常
        均静默吞掉，调用方以「抓不到就判 skip/降级」处理，不抛异常打断场景流程）。"""
        lines = []
        deadline = time.time() + total_timeout
        resp = None
        try:
            resp = self.csrf.request(
                "GET", "/api/service/logs", timeout=(10, idle_timeout), stream=True,
                params={"skip": self._skip_from})
            if resp.status_code != 200:
                return ""
            for raw in resp.iter_lines(decode_unicode=True):
                if time.time() >= deadline:
                    break
                if not raw or not raw.startswith("data:"):
                    continue
                payload = raw[5:].strip()
                if payload == "[DONE]":
                    break
                try:
                    obj = json.loads(payload)
                except Exception:
                    continue
                if isinstance(obj, dict) and "line" in obj:
                    lines.append(str(obj["line"]))
                elif isinstance(obj, dict) and "error" in obj:
                    break
        except Exception:
            pass
        finally:
            if resp is not None:
                try:
                    resp.close()
                except Exception:
                    pass
        return "\n".join(lines)

    def last_prompt_block(self):
        """本次 `mark()` 之后产生的最后一个最终提示词块；抓不到返回空字符串（调用方据此判
        skip/降级，与 `_PromptLogProbe.last_prompt_block()` 语义一致，复用同一条正则）。"""
        blocks = _PF_PROMPT_BLOCK_RE.findall(self.read_new())
        return blocks[-1] if blocks else ""


class QAIModelBuilderLocalModelTester:
    _MODEL_PLACEHOLDER = "_builder_local_model_"
    # backend → format 字段值（GET /api/service/models 的判定），infer_backend 用 "GGUF" 表示
    # GGUF 后端，Builder /api/service/models 返回的是小写 "gguf"，注意这里的映射。
    _BACKEND_TO_FORMAT = {"qnn": "qnn", "mnn": "mnn", "GGUF": "gguf"}

    def __init__(self, builder, models_root, genie_root_path, model_names,
                 genie_service_port, round_num=1, data_dir=None):
        self.builder = builder
        self.models_root = Path(models_root) if models_root else None
        self.genie_root_path = genie_root_path
        self.model_names = list(model_names)
        self.genie_service_port = genie_service_port
        self.round_num = round_num
        self.data_dir = data_dir
        self.results = []
        self.crash_events = []
        # configure_genie_root() 里 mklink /J 联接的 <data_dir>/bin/<name> 路径（当前无读取方，
        # 原消费方 test_invalid_genie_root() 已随过时的 builder_local_model 套件一并删除，
        # 见 test_builder_agent_tasks.py 的真实多轮 agent 测试；此字段保留供未来同类用例复用）。
        self._bin_junction_path = None
        # 本次创建的全部 mklink /J 联接目标（bin + models），cleanup_junctions() 消费；
        # 见该方法文档字符串，必须在 finally 里无条件调用，否则会复现 docs/known-issues.md
        # 7.1b 根因③（残留联接被远程同步 git clean -fd 顺着删除真实目录下的文件）。
        self._junction_paths = []
        # 模型目录安全网：inject_local_models() 成功后拍快照，_sc_case_builder_e2e() 的
        # finally 块无论用例成败都会调用 verify()，防止 mklink /J 联接被 Builder 安装/更新/
        # 删除路径透明穿透地误改/误删真实模型目录下的配置文件。
        self.model_dir_snapshot = ModelDirSnapshot()

    def _make_result(self, name, passed, status_code, detail, *,
                     model_name=None, skipped=False, crashed=False, ignorable=False,
                     response_data=None, latency_ms=0):
        return TestResult(
            name=name, round_num=self.round_num,
            model_name=model_name or self._MODEL_PLACEHOLDER,
            passed=passed, status_code=status_code, latency_ms=latency_ms,
            detail=detail, skipped=skipped, crashed=crashed,
            ignorable=ignorable,
            response_data=response_data or {},
        )

    def _csrf_request(self, method, path, *, body=None, timeout=30):
        """封装一次带 CSRF 头的 Builder API 请求，返回 (response_or_exception, latency_ms)。
        请求异常时不抛出，返回 (exception, latency) 供调用方按 result 记录；主动区分"HTTP 异常"
        与"Builder 进程崩溃"两种情况（后者由 builder.process.poll() 判断）。"""
        start = time.time()
        try:
            if body is None:
                r = self.builder.csrf.request(method, path, timeout=timeout)
            else:
                r = self.builder.csrf.request(method, path, timeout=timeout, json=body)
            return r, (time.time() - start) * 1000
        except Exception as e:
            return e, (time.time() - start) * 1000

    # ---- Step 2: configure_genie_root ----
    def configure_genie_root(self):
        """把 GenieAPIService 安装目录通过 mklink /J 联接到 Builder 固定扫描的
        <data_dir>/bin/<name> 下，触发 Builder 官方的"自动发现已安装版本"自愈机制。

        POST /api/forge-config 写入的 genie_service.root_path 持久化到 SQLite 的
        kv_user_prefs 表，而服务启动时真正解析安装目录的 _make_install_dir_provider
        读取的是磁盘上的 <data_dir>/config/forge_config.json 纯 JSON 文件——两套持久化
        后端完全独立、互不联通，因此该 HTTP 接口对 root_path 的写入不会被服务启动路径
        实际读取到。正确路径是 _make_install_dir_provider 每次请求都会实时扫描
        <data_dir>/bin/ 下的子目录，一旦发现某个子目录直接包含 GenieAPIService.exe 就会
        自愈式地把它当作已安装版本使用，与下载中心真实安装一个新版本效果一致且不需要
        重启 Builder。这里通过纯文件系统操作（mklink /J）达成，不依赖也不修改
        forge-config 相关 HTTP 接口。"""
        name = "BUILDER-LOCAL: configure_genie_root (mklink /J into data_dir/bin)"
        if not self.genie_root_path:
            self.results.append(self._make_result(
                name, False, 0,
                "未提供 GenieAPIService 安装目录（--genie_root_path 或 --exe_dir），跳过",
                skipped=True))
            return False
        src = Path(self.genie_root_path)
        if not src.is_dir() or not (src / "GenieAPIService.exe").is_file():
            self.results.append(self._make_result(
                name, False, 0,
                f"--genie_root_path 不存在或不含 GenieAPIService.exe: {src}"))
            return False
        if not self.builder.data_dir:
            self.results.append(self._make_result(
                name, False, 0,
                "Builder 未启用隔离数据目录 (QAI_DATA__DATA_DIR)，无法注入安装目录",
                skipped=True))
            return False

        bin_root = self.builder.data_dir / "bin"
        try:
            bin_root.mkdir(parents=True, exist_ok=True)
        except Exception as e:
            self.results.append(self._make_result(
                name, False, 0, f"创建 {bin_root} 失败: {e}"))
            return False

        dst = bin_root / src.name
        self._bin_junction_path = dst
        self._junction_paths.append(dst)
        if not dst.exists():
            try:
                proc = subprocess.run(
                    ["cmd.exe", "/c", "mklink", "/J", str(dst), str(src)],
                    capture_output=True, text=True, timeout=15,
                )
            except Exception as e:
                self.results.append(self._make_result(
                    name, False, 0, f"mklink /J subprocess 异常: {type(e).__name__}: {e}"))
                return False
            if proc.returncode != 0:
                stderr = (proc.stderr or "").strip()
                stdout = (proc.stdout or "").strip()
                self.results.append(self._make_result(
                    name, False, 0,
                    f"mklink /J 失败, rc={proc.returncode}, stderr={stderr!r}, stdout={stdout!r}; "
                    f"dst={dst}, src={src}"))
                return False

        r_status, latency = self._csrf_request("GET", "/api/service/status", timeout=15)
        if isinstance(r_status, Exception) or r_status.status_code != 200:
            self.results.append(self._make_result(
                name, False, getattr(r_status, "status_code", 0),
                f"GET /api/service/status 读取失败: {r_status}", latency_ms=latency))
            return False
        try:
            js = r_status.json()
        except Exception as e:
            self.results.append(self._make_result(
                name, False, r_status.status_code,
                f"status 响应体不是 JSON: {e}", latency_ms=latency))
            return False
        exe_path = js.get("exe_path")
        path_warning = js.get("path_warning")
        passed = bool(exe_path) and (src.name.lower() in str(exe_path).lower())
        self.results.append(self._make_result(
            name, passed, 200,
            (f"mklink /J 注入完成: {dst} -> {src}; exe_path={exe_path}; "
             f"path_warning={path_warning}"),
            latency_ms=latency,
            response_data={"bin_junction": str(dst), "exe_path": exe_path,
                           "path_warning": path_warning}))
        return passed

    # ---- Step 2: inject_local_models ----
    def inject_local_models(self):
        """用 mklink /J 把每个 --models/<name> 目录联接到 <data_dir>/models/<name>。
        Builder 的 models_root_path 已固定为 <data_dir>/models（Builder 侧移除了修改根目录的
        API），通过纯文件系统操作让本机已有模型出现在扫描目录下，无需复制大文件、也不侵入
        Builder 源码。"""
        name = "BUILDER-LOCAL: inject_local_models (mklink /J)"
        if not self.models_root or not self.models_root.exists():
            self.results.append(self._make_result(
                name, False, 0,
                f"--models 目录不可用（models_root={self.models_root}），跳过注入",
                skipped=True))
            return False
        if not self.builder.data_dir:
            self.results.append(self._make_result(
                name, False, 0,
                "Builder 未启用隔离数据目录 (QAI_DATA__DATA_DIR)，无法注入本地模型",
                skipped=True))
            return False
        target_models_root = self.builder.data_dir / "models"
        try:
            target_models_root.mkdir(parents=True, exist_ok=True)
        except Exception as e:
            self.results.append(self._make_result(
                name, False, 0,
                f"创建目标模型根目录失败: {target_models_root}: {e}"))
            return False

        successes = []
        failures = []
        snapshot_targets = []  # 联接成功（含幂等已存在）的真实模型目录，供 ModelDirSnapshot.snapshot() 使用
        for m in self.model_names:
            src = self.models_root / m
            if not src.exists():
                failures.append(f"{m}(源目录不存在: {src})")
                continue
            dst = target_models_root / m
            self._junction_paths.append(dst)
            if dst.exists():
                successes.append(f"{m}(目标已存在，视作幂等成功)")
                snapshot_targets.append(src)
                continue
            try:
                proc = subprocess.run(
                    ["cmd.exe", "/c", "mklink", "/J", str(dst), str(src)],
                    capture_output=True, text=True, timeout=15,
                )
            except Exception as e:
                failures.append(f"{m}(subprocess 异常: {type(e).__name__}: {e})")
                continue
            if proc.returncode != 0:
                stderr = (proc.stderr or "").strip()
                stdout = (proc.stdout or "").strip()
                failures.append(
                    f"{m}(mklink /J 失败, rc={proc.returncode}, stderr={stderr!r}, stdout={stdout!r})")
                continue
            successes.append(m)
            snapshot_targets.append(src)

        # 模型目录安全网：联接一旦建立（无论新建还是幂等复用），Windows 对该联接路径的任何
        # 文件系统操作都会透明穿透到 src（真实模型目录）——此处对 src 而非 dst 拍照，
        # 语义上等价且不依赖联接本身是否在收尾时仍然存在。
        if snapshot_targets:
            self.model_dir_snapshot.snapshot(snapshot_targets)

        detail = (f"注入 {len(successes)}/{len(self.model_names)}; "
                  f"successes={successes}; failures={failures}; target={target_models_root}")
        passed = bool(successes) and not failures
        self.results.append(self._make_result(
            name, passed, 0, detail,
            response_data={"target_models_root": str(target_models_root),
                           "successes": successes, "failures": failures}))
        return bool(successes)

    def cleanup_junctions(self):
        """收尾：移除本实例 configure_genie_root()/inject_local_models() 创建的全部
        联接（委托模块级 cleanup_junctions()）。调用方须在 finally 里无条件调用。"""
        cleanup_junctions(self._junction_paths)

    # ---- Step 3: discover_models via Builder ----
    def discover_models_via_builder(self):
        """调用 GET /api/service/models，与本地 infer_backend() 交叉校验 format 字段。
        返回 Builder 侧发现的模型清单（原始 entries）。"""
        name = "BUILDER-LOCAL: discover_models (GET /api/service/models)"
        r, latency = self._csrf_request("GET", "/api/service/models", timeout=30)
        if isinstance(r, Exception):
            self.results.append(self._make_result(
                name, False, 0,
                f"GET /api/service/models 请求异常: {type(r).__name__}: {r}",
                latency_ms=latency))
            return []
        if r.status_code != 200:
            self.results.append(self._make_result(
                name, False, r.status_code,
                f"GET /api/service/models 非 200: body={r.text[:300]}",
                latency_ms=latency))
            return []
        try:
            js = r.json()
        except Exception as e:
            self.results.append(self._make_result(
                name, False, 200, f"响应体不是 JSON: {e}", latency_ms=latency))
            return []
        found = js.get("models") or []
        expected = set(self.model_names)
        found_names = {m.get("name") for m in found if isinstance(m, dict)}
        missing = sorted(expected - found_names)
        mismatches = []
        for entry in found:
            if not isinstance(entry, dict):
                continue
            nm = entry.get("name")
            if nm not in expected:
                continue
            backend, _dev = infer_backend(nm)
            expected_fmt = self._BACKEND_TO_FORMAT.get(backend, "").lower()
            actual_fmt = str(entry.get("format") or "").lower()
            if expected_fmt and actual_fmt and actual_fmt != expected_fmt:
                mismatches.append(f"{nm}: expected={expected_fmt}, got={actual_fmt}")
        passed = not missing and not mismatches
        self.results.append(self._make_result(
            name, passed, 200,
            (f"发现 {len(found)} 个模型；期望 {sorted(expected)}, "
             f"实际匹配 {sorted(found_names & expected)}; missing={missing}; "
             f"format_mismatches={mismatches}; models_root_path={js.get('models_root_path')}"),
            latency_ms=latency,
            response_data={"models": found,
                           "models_root_path": js.get("models_root_path")}))
        return found

    # ---- Step 3: start_and_wait_ready ----
    def start_and_wait_ready(self, model_name, port, timeout=240):
        """POST /api/service/start 后自行轮询 GET /api/service/status 直到 running=true
        且 model 匹配（该接口是 fire-and-forget，不阻塞等待）。"""
        name = f"BUILDER-LOCAL: start_and_wait_ready model={model_name}"
        body = {"model_name": model_name, "port": port}
        r, latency = self._csrf_request("POST", "/api/service/start", body=body, timeout=30)
        if isinstance(r, Exception):
            self.results.append(self._make_result(
                name, False, 0,
                f"POST /api/service/start 请求异常: {type(r).__name__}: {r}",
                model_name=model_name, latency_ms=latency))
            return False, None
        if r.status_code not in (200, 201, 202):
            self.results.append(self._make_result(
                name, False, r.status_code,
                f"POST /api/service/start 非成功状态码: body={r.text[:300]}",
                model_name=model_name, latency_ms=latency))
            return False, None
        # 轮询 status 直到 running=true 且 model 匹配
        started_at = time.time()
        end = started_at + timeout
        last_status = None
        while time.time() < end:
            rs, _ = self._csrf_request("GET", "/api/service/status", timeout=10)
            if not isinstance(rs, Exception) and rs.status_code == 200:
                try:
                    last_status = rs.json()
                except Exception:
                    last_status = None
                if isinstance(last_status, dict) and last_status.get("running") \
                        and last_status.get("model") == model_name:
                    total_ms = (time.time() - started_at) * 1000
                    self.results.append(self._make_result(
                        name, True, 200,
                        (f"服务已就绪: state={last_status.get('state')}, "
                         f"pid={last_status.get('pid')}, model={last_status.get('model')}, "
                         f"port={last_status.get('port')}"),
                        model_name=model_name, latency_ms=total_ms,
                        response_data=last_status))
                    return True, last_status
            time.sleep(2)
        self.results.append(self._make_result(
            name, False, 0,
            f"轮询 {timeout}s 未看到 running=true 且 model={model_name}; last_status={last_status}",
            model_name=model_name))
        return False, last_status

    # ---- Step 4: stop_and_verify ----
    def stop_and_verify(self, port):
        name = "BUILDER-LOCAL: stop_and_verify (POST /api/service/stop)"
        r, latency = self._csrf_request(
            "POST", "/api/service/stop", body={"force": False}, timeout=30)
        if isinstance(r, Exception):
            self.results.append(self._make_result(
                name, False, 0,
                f"POST /api/service/stop 请求异常: {type(r).__name__}: {r}",
                latency_ms=latency))
            return False
        end = time.time() + 30
        stopped = False
        last_status = None
        while time.time() < end:
            rs, _ = self._csrf_request("GET", "/api/service/status", timeout=10)
            if not isinstance(rs, Exception) and rs.status_code == 200:
                try:
                    last_status = rs.json()
                except Exception:
                    last_status = None
                if isinstance(last_status, dict) and not last_status.get("running"):
                    stopped = True
                    break
            time.sleep(1)
        port_released = wait_port_closed("127.0.0.1", port, timeout=15)
        passed = stopped and port_released
        self.results.append(self._make_result(
            name, passed, r.status_code,
            f"stopped={stopped}, port_released={port_released}, last_status={last_status}",
            latency_ms=latency,
            response_data={"stopped": stopped, "port_released": port_released,
                           "last_status": last_status}))
        return passed



# ============================================================================
# -n -1 vs -n 30 差异化自验证矩阵（直接启动路径，不经 QAIModelBuilder）
# ============================================================================
# Builder 启动 GenieAPIService.exe 时固定 loglevel=3(kInfo)，且结构性无法同步读取子进程
# 自身的日志文件（只有 SSE 流），因此下面 4 项行为差异（历史管理/系统提示词优化/工具定义
# 优化/长文本摘要，均只在 numResponse==-1 时触发）只能在这条不经 Builder、由测试脚本自己
# 用 ServiceManager 直接启动裸 GenieAPIService.exe、可自由传 -d 4 的路径里，通过读取
# stdout 日志文件真正坐实。

_STATELESS_MODE_READ_TOOL_DEF = {
    "type": "function",
    "function": {
        "name": "read",
        "description": "Read the content of a file at the given path.",
        "parameters": {
            "type": "object",
            "properties": {"path": {"type": "string", "description": "File path to read"}},
            "required": ["path"],
        },
    },
}


_STATELESS_MODE_SYSPROMPT_MARKER = "[Optimization] System prompt rebuilt:"
_STATELESS_MODE_LONGTEXT_TRIGGER_MARKER = "[LongTextSummarizer][Map] chunk 1/"
_STATELESS_MODE_LONGTEXT_SUCCESS_MARKER = "[LongTextSummarizer] User message summarized:"
_STATELESS_MODE_LONGTEXT_REDUCE_FAIL_MARKER = "[LongTextSummarizer] Reduce failed"
_STATELESS_MODE_LONGTEXT_TIMEOUT_S = 900


def _read_long_text_trigger_ratio(exe_dir):
    """从构建产物目录下实际生效的 prompt_engineering.json 读取
    prompt_optimization.long_text_summarization.trigger_ratio；读取不到时按 0.5 兜底
    （与代码默认值一致，见 prompt_engineering.json 中的同名字段注释）。"""
    default_ratio = 0.5
    try:
        cfg_path = Path(exe_dir) / "config" / "prompt_engineering.json"
        with open(cfg_path, "r", encoding="utf-8") as f:
            cfg = json.load(f)
        ratio = ((cfg.get("prompt_optimization") or {}).get("long_text_summarization") or {}).get("trigger_ratio")
        if isinstance(ratio, (int, float)) and ratio > 0:
            return float(ratio)
    except Exception:
        pass
    return default_ratio


def _build_stateless_long_text_probe(context_size, trigger_ratio):
    """按 context_size × trigger_ratio 换算出安全超阈值的重复文本长度（字符数）。用一个
    宁可偏大的 token→字符换算系数(约2字符/token)叠加安全系数，确保稳定超过触发阈值，
    不卡在临界值附近；context_size 读取失败/为 0 时退回一个保守默认值。"""
    if not context_size or context_size <= 0:
        context_size = 4096
    filler = "The quick brown fox jumps over the lazy dog while testing long text summarization triggers. "
    chars_needed = int(context_size * trigger_ratio * 2.0 * 1.3)
    chars_needed = max(chars_needed, len(filler) * 4)
    reps = chars_needed // len(filler) + 2
    return (filler * reps)[:chars_needed]


def _stateless_chat_request(host, port, model_name, user_content, tools=None, timeout=180):
    """直接向裸启动的 GenieAPIService.exe 发一次非流式 chat 请求(不经 Builder,不带任何
    OpenClaw header),返回 (requests.Response|None, error_str|None)。"""
    body = {
        "model": model_name,
        "messages": [{"role": "user", "content": user_content}],
        "stream": False,
        "max_tokens": 64,
    }
    if tools:
        body["tools"] = tools
    try:
        r = requests.post(f"http://{host}:{port}/v1/chat/completions", json=body, timeout=timeout)
        return r, None
    except Exception as e:
        return None, f"{type(e).__name__}: {e}"


def run_numresponse_stateless_mode_regressions(args, models, all_results, all_crash_events, all_perf_samples):
    """不经 QAIModelBuilder 的 `-n -1` vs `-n 30` 自验证矩阵：对同一批探针请求分别用
    `-n -1 -d 4` 与 `-n 30 -d 4`（默认对照组）各启动一次裸 GenieAPIService.exe（两次完全
    独立的服务生命周期,先完整停止第一组再启动第二组,不做进程内热切换——numResponse 是
    进程级全局配置,无法运行时切换）。架构事实（已读 model_input_builder.h 源码核实）：
    压缩管线（系统提示词优化/工具定义优化/长文本摘要）对两种模式完全统一调用、无任何
    `-n` 分支，三者按"一致性断言"（两侧必须同时出现日志）核验；只有历史管理
    （`[History] Skipped` vs `✓ Added`）是真实存在的差异——`IsStatelessMode()` 唯一的
    用途是在 response_dispatcher.cpp 决定客户端断开后是否把历史持久化在服务端，与压缩
    管线无关——该探针按"双向断言"（互斥出现）核验。全方案里唯一能通过读日志真正坐实
    这些差异/一致性确实按预期发生的地方（Builder 路径固定 loglevel=3 且结构性无法同步
    读子进程日志）。
    """
    print(f"\n{'='*60}")
    print("阶段: -n -1 vs -n 30 差异化自验证矩阵（历史管理/系统提示词优化/工具定义优化/长文本摘要）")
    print(f"{'='*60}")
    name_prefix = "STATELESS-MODE:"
    placeholder_model = "_stateless_mode_"
    model_name = _pick_builder_integration_model(models)

    if args.remote:
        all_results.append(TestResult(
            name=f"{name_prefix} -n -1 vs -n 30 差异化验证", round_num=1,
            model_name=model_name or placeholder_model,
            passed=False, status_code=0, latency_ms=0,
            detail="远程模式无法临时切换本地服务启动参数(-n/-d)，跳过差异化自验证矩阵",
            skipped=True
        ))
        return
    if not model_name:
        all_results.append(TestResult(
            name=f"{name_prefix} -n -1 vs -n 30 差异化验证", round_num=1, model_name=placeholder_model,
            passed=False, status_code=0, latency_ms=0,
            detail="未发现可用于该差异化验证矩阵的模型", skipped=True
        ))
        return

    config_path = Path(args.models) / model_name / "config.json"
    if not config_path.exists():
        all_results.append(TestResult(
            name=f"{name_prefix} -n -1 vs -n 30 差异化验证", round_num=1, model_name=model_name,
            passed=False, status_code=0, latency_ms=0,
            detail=f"找不到 config.json: {config_path}", skipped=True
        ))
        return

    read_tool = [_STATELESS_MODE_READ_TOOL_DEF]
    trigger_ratio = _read_long_text_trigger_ratio(args.exe_dir)

    modes = (("-1", ["-n", "-1", "-d", "4"]), ("30", ["-n", "30", "-d", "4"]))
    mode_data = {}

    for mode_label, extra_args in modes:
        svc = ServiceManager(args.exe_dir, args.host, args.port)
        svc._log_dir = str(Path(args.out_dir) / f"stateless_mode_n_{mode_label.replace('-', 'minus')}")
        perf = PerfMonitor()
        try:
            print(f"  启动服务 (-n {mode_label} -d 4): {model_name}")
            svc.start(str(config_path), extra_args=extra_args)
            if not wait_port_open(args.host, args.port, timeout=120, process=svc.process):
                raise RuntimeError(f"端口 120s 内未可连接 (-n {mode_label})")
            pid = svc.get_pid()
            if pid:
                perf.start(pid)

            data = {}

            # 探针1+2：历史管理 + 系统提示词优化（复用同一次请求产生的日志）
            resp1, err1 = _stateless_chat_request(args.host, args.port, model_name,
                                                    "请记住这句话，并用一句话简短确认。")
            data["hist_sysprompt_resp"] = resp1
            data["hist_sysprompt_err"] = err1
            data["hist_sysprompt_log"] = svc.read_log_tail(svc._stdout_log, 600)

            # 探针3：工具定义优化（必须用预定义工具名 "read" 才能保证产生确定性差异）
            resp3, err3 = _stateless_chat_request(args.host, args.port, model_name,
                                                    "Please call the read tool to read README.md.",
                                                    tools=read_tool)
            data["tool_resp"] = resp3
            data["tool_err"] = err3
            data["tool_log"] = svc.read_log_tail(svc._stdout_log, 600)

            # 探针4：长文本摘要（先查真实 context_size，再按 trigger_ratio 动态换算超阈值长度）
            context_size = 0
            try:
                ctx_r = requests.post(f"http://{args.host}:{args.port}/contextsize",
                                       json={"model": model_name}, timeout=30)
                if ctx_r.status_code == 200:
                    context_size = ctx_r.json().get("contextsize", 0)
            except Exception:
                pass
            long_text = _build_stateless_long_text_probe(context_size, trigger_ratio)
            resp4, err4 = _stateless_chat_request(args.host, args.port, model_name, long_text,
                                                    timeout=_STATELESS_MODE_LONGTEXT_TIMEOUT_S)
            data["longtext_resp"] = resp4
            data["longtext_err"] = err4
            data["longtext_log"] = svc.read_log_tail(svc._stdout_log, 800)
            data["context_size"] = context_size

            # /clear /fetch /contextsize：验证该模式下基础接口不因"是否维护历史"这一行为
            # 差异而返回异常状态码/结构。
            try:
                data["clear_resp"] = requests.post(f"http://{args.host}:{args.port}/clear",
                                                     json={"text": "clear"}, timeout=30)
            except Exception as e:
                data["clear_resp"] = None
                data["clear_err"] = f"{type(e).__name__}: {e}"
            try:
                data["fetch_resp"] = requests.post(f"http://{args.host}:{args.port}/fetch",
                                                     json={}, timeout=30)
            except Exception as e:
                data["fetch_resp"] = None
                data["fetch_err"] = f"{type(e).__name__}: {e}"
            try:
                data["contextsize_resp"] = requests.post(f"http://{args.host}:{args.port}/contextsize",
                                                            json={"model": model_name}, timeout=30)
            except Exception as e:
                data["contextsize_resp"] = None
                data["contextsize_err"] = f"{type(e).__name__}: {e}"

            mode_data[mode_label] = data
        except (RuntimeError, FileNotFoundError) as e:
            print(f"  ✗ (-n {mode_label}) 服务启动失败: {e}")
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name=model_name, round_num=1,
                endpoint="STATELESS_MODE_SERVICE_STARTUP", detail=str(e),
                log_tail=_capture_log_tail(svc),
            ))
            all_results.append(TestResult(
                name=f"{name_prefix} 服务启动 (-n {mode_label})", round_num=1, model_name=model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"启动失败: {str(e)[:300]}", crashed=True
            ))
            mode_data[mode_label] = None
        except Exception as e:
            print(f"  ✗ (-n {mode_label}) 差异化验证阶段异常: {e}")
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name=model_name, round_num=1,
                endpoint="STATELESS_MODE_REGRESSION", detail=str(e),
                log_tail=_capture_log_tail(svc),
            ))
            all_results.append(TestResult(
                name=f"{name_prefix} 探针执行 (-n {mode_label})", round_num=1, model_name=model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"测试异常: {str(e)[:300]}", crashed=True
            ))
            mode_data[mode_label] = None
        finally:
            perf_samples = perf.stop()
            all_perf_samples.extend(perf_samples)
            print(f"  停止服务 (-n {mode_label})...")
            svc.stop()
            # 两次生命周期必须完全独立：确认端口真正释放后才进入下一组启动，
            # 避免上一个进程刚被结束、TCP 端口仍处于释放延迟阶段就抢跑下一次 start。
            wait_port_closed(args.host, args.port, timeout=15)

    data_neg1 = mode_data.get("-1")
    data_30 = mode_data.get("30")

    # ── 探针1：历史管理（双向断言：该出现的必须出现，该不出现的必须不出现） ──────
    try:
        name = f"{name_prefix} 历史管理 ([History] Skipped vs ✓ Added，双向断言)"
        if data_neg1 is None or data_30 is None:
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=False, status_code=0, latency_ms=0,
                detail="其中一侧服务未能成功启动/完成探针请求，无法完成双向比对", skipped=True
            ))
        else:
            log_neg1 = data_neg1["hist_sysprompt_log"]
            log_30 = data_30["hist_sysprompt_log"]
            neg1_has_skipped = "[History] Skipped (numResponse == -1, client manages history)" in log_neg1
            neg1_has_added = "[History] ✓ Added assistant message" in log_neg1
            mode30_has_skipped = "[History] Skipped (numResponse == -1, client manages history)" in log_30
            mode30_has_added = "[History] ✓ Added assistant message" in log_30
            passed = neg1_has_skipped and not neg1_has_added and mode30_has_added and not mode30_has_skipped
            detail = (f"-1侧: skipped={neg1_has_skipped}, added={neg1_has_added}; "
                      f"30侧: skipped={mode30_has_skipped}, added={mode30_has_added}")
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=passed, status_code=200 if passed else 0,
                latency_ms=0, detail=detail
            ))
    except Exception as e:
        all_results.append(TestResult(
            name=f"{name_prefix} 历史管理双向断言", round_num=1, model_name=model_name,
            passed=False, status_code=0, latency_ms=0, detail=f"用例异常: {type(e).__name__}: {e}", crashed=True
        ))

    # ── 探针2：系统提示词优化（一致性断言：压缩管线不分 -n 分支，两侧必须同时出现日志） ──
    # 架构事实（已读 model_input_builder.h 源码核实，`BuildTaskMemoSection`/`ApplyFitMessagesToContext`
    # 等调用点在 General/Harmony 两路径均对称存在，无任何 `numResponse()==-1`/`IsStatelessMode()` 判断）：
    # PreFilterMessages/FitMessagesToContext/系统提示词优化等压缩管线对 `-n -1`（无状态）与 `-n` 正整数
    # （有状态）两种模式完全统一调用，没有分支；`IsStatelessMode()`/`GetEffectiveStatelessMode()`
    # 唯一的真实用途在 response_dispatcher.cpp，只决定是否在客户端断开后把历史持久化在服务端（即
    # 上面探针1验证的 `[History] Skipped` vs `✓ Added` 差异），与本探针验证的压缩管线完全无关。
    # 曾错误断言 `30` 侧不应出现该日志（旧假设：压缩管线按 -n 分支），已被真机回归证伪并纠正于此。
    # 判据标记取自 model_input_builder.h 的实际 kInfo 输出，不要改回已不存在的 savings 文案
    # （理由见 test_service.md「探针标记必须对齐源码实际输出」）。
    try:
        name = f"{name_prefix} 系统提示词优化 ([Optimization] System prompt rebuilt，一致性断言)"
        if data_neg1 is None or data_30 is None:
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=False, status_code=0, latency_ms=0,
                detail="其中一侧服务未能成功启动/完成探针请求，无法完成一致性比对", skipped=True
            ))
        else:
            log_neg1 = data_neg1["hist_sysprompt_log"]
            log_30 = data_30["hist_sysprompt_log"]
            neg1_has_savings = _STATELESS_MODE_SYSPROMPT_MARKER in log_neg1
            mode30_has_savings = _STATELESS_MODE_SYSPROMPT_MARKER in log_30
            passed = neg1_has_savings and mode30_has_savings
            detail = f"-1侧出现rebuilt日志={neg1_has_savings}; 30侧出现rebuilt日志={mode30_has_savings}（两侧应一致）"
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=passed, status_code=200 if passed else 0,
                latency_ms=0, detail=detail
            ))
    except Exception as e:
        all_results.append(TestResult(
            name=f"{name_prefix} 系统提示词优化一致性断言", round_num=1, model_name=model_name,
            passed=False, status_code=0, latency_ms=0, detail=f"用例异常: {type(e).__name__}: {e}", crashed=True
        ))

    # ── 探针3：工具定义优化（一致性断言，须用预定义工具名 "read"；原理同探针2，压缩管线不分 -n 分支）──
    try:
        name = f"{name_prefix} 工具定义优化 ([Optimizer] Tools - Original...Savings...，一致性断言)"
        if data_neg1 is None or data_30 is None:
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=False, status_code=0, latency_ms=0,
                detail="其中一侧服务未能成功启动/完成探针请求，无法完成一致性比对", skipped=True
            ))
        else:
            log_neg1 = data_neg1["tool_log"]
            log_30 = data_30["tool_log"]
            neg1_has_tool_opt = ("[Optimizer] Tools - Original:" in log_neg1) and ("Savings:" in log_neg1)
            mode30_has_tool_opt = ("[Optimizer] Tools - Original:" in log_30) and ("Savings:" in log_30)
            passed = neg1_has_tool_opt and mode30_has_tool_opt
            detail = f"-1侧出现工具优化日志={neg1_has_tool_opt}; 30侧出现工具优化日志={mode30_has_tool_opt}（两侧应一致）"
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=passed, status_code=200 if passed else 0,
                latency_ms=0, detail=detail
            ))
    except Exception as e:
        all_results.append(TestResult(
            name=f"{name_prefix} 工具定义优化一致性断言", round_num=1, model_name=model_name,
            passed=False, status_code=0, latency_ms=0, detail=f"用例异常: {type(e).__name__}: {e}", crashed=True
        ))

    # ── 探针4：长文本摘要（一致性断言；原理同探针2/3，压缩管线不分 -n 分支） ──────────
    # 判据是"Map 阶段被触发"而不是"摘要成功"：成功标记只在 Reduce 收敛时才打印，而 Reduce 能否在
    # 服务端 300s 推理预算内收敛取决于模型、与 -n 无关（实测两次运行一次成功一次撞预算回退原文）。
    # 请求超时仍需覆盖整条 Map-Reduce 链，否则客户端先断开、探针会在标记落盘前读快照。
    # 实测数字与判据选择理由见 test_service.md「探针4 的判据与超时」。
    try:
        name = f"{name_prefix} 长文本摘要 ([LongTextSummarizer][Map] chunk 1/N，一致性断言)"
        if data_neg1 is None or data_30 is None:
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=False, status_code=0, latency_ms=0,
                detail="其中一侧服务未能成功启动/完成探针请求，无法完成一致性比对", skipped=True
            ))
        else:
            log_neg1 = data_neg1["longtext_log"]
            log_30 = data_30["longtext_log"]
            neg1_triggered = _STATELESS_MODE_LONGTEXT_TRIGGER_MARKER in log_neg1
            mode30_triggered = _STATELESS_MODE_LONGTEXT_TRIGGER_MARKER in log_30
            passed = neg1_triggered and mode30_triggered
            detail = (f"context_size(-1侧)={data_neg1.get('context_size')}, "
                      f"context_size(30侧)={data_30.get('context_size')}, trigger_ratio={trigger_ratio}; "
                      f"-1侧 Map 被触发={neg1_triggered}; 30侧 Map 被触发={mode30_triggered}（两侧应一致）; "
                      f"Reduce 成功(-1侧)={_STATELESS_MODE_LONGTEXT_SUCCESS_MARKER in log_neg1}, "
                      f"Reduce 成功(30侧)={_STATELESS_MODE_LONGTEXT_SUCCESS_MARKER in log_30}, "
                      f"Reduce 回退原文(-1侧)={_STATELESS_MODE_LONGTEXT_REDUCE_FAIL_MARKER in log_neg1}, "
                      f"Reduce 回退原文(30侧)={_STATELESS_MODE_LONGTEXT_REDUCE_FAIL_MARKER in log_30}; "
                      f"timeout={_STATELESS_MODE_LONGTEXT_TIMEOUT_S}s, 请求异常(-1侧)={data_neg1.get('longtext_err')}, "
                      f"请求异常(30侧)={data_30.get('longtext_err')}")
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=passed, status_code=200 if passed else 0,
                latency_ms=0, detail=detail
            ))
    except Exception as e:
        all_results.append(TestResult(
            name=f"{name_prefix} 长文本摘要一致性断言", round_num=1, model_name=model_name,
            passed=False, status_code=0, latency_ms=0, detail=f"用例异常: {type(e).__name__}: {e}", crashed=True
        ))

    # ── /clear /fetch /contextsize：两组均需返回预期状态码/结构 ────────────────
    def _check_basic_endpoint(endpoint_label, resp_key_prefix, judge_fn):
        try:
            name = f"{name_prefix} {endpoint_label}（-1/30 两组均需通过）"
            if data_neg1 is None or data_30 is None:
                all_results.append(TestResult(
                    name=name, round_num=1, model_name=model_name, passed=False, status_code=0, latency_ms=0,
                    detail="其中一侧服务未能成功启动/完成探针请求，无法完成校验", skipped=True
                ))
                return
            resp_neg1 = data_neg1.get(f"{resp_key_prefix}_resp")
            resp_30 = data_30.get(f"{resp_key_prefix}_resp")
            ok_neg1, detail_neg1 = judge_fn(resp_neg1)
            ok_30, detail_30 = judge_fn(resp_30)
            passed = ok_neg1 and ok_30
            detail = f"-1侧: {detail_neg1}; 30侧: {detail_30}"
            all_results.append(TestResult(
                name=name, round_num=1, model_name=model_name, passed=passed,
                status_code=200 if passed else 0, latency_ms=0, detail=detail
            ))
        except Exception as e:
            all_results.append(TestResult(
                name=f"{name_prefix} {endpoint_label}", round_num=1, model_name=model_name,
                passed=False, status_code=0, latency_ms=0, detail=f"用例异常: {type(e).__name__}: {e}", crashed=True
            ))

    def _judge_clear(resp):
        if resp is None:
            return False, "请求失败"
        return resp.status_code == 200, f"status={resp.status_code}"

    def _judge_fetch(resp):
        if resp is None:
            return False, "请求失败"
        if resp.status_code != 200:
            return False, f"status={resp.status_code}"
        try:
            body = resp.json()
            return "history" in body, f"status=200, 含history字段={('history' in body)}"
        except Exception as e:
            return False, f"JSON解析失败: {e}"

    def _judge_contextsize(resp):
        if resp is None:
            return False, "请求失败"
        if resp.status_code != 200:
            return False, f"status={resp.status_code}"
        try:
            ctx = resp.json().get("contextsize", 0)
            return ctx > 0, f"status=200, contextsize={ctx}"
        except Exception as e:
            return False, f"JSON解析失败: {e}"

    _check_basic_endpoint("POST /clear", "clear", _judge_clear)
    _check_basic_endpoint("POST /fetch", "fetch", _judge_fetch)
    _check_basic_endpoint("POST /contextsize", "contextsize", _judge_contextsize)


def run_gguf_explicit_load_regressions(args, models, all_results, all_crash_events, all_perf_samples):
    """阶段 4：对全部已发现的 GGUF 模型（或 --gguf_model 限定的单个模型），分别用
    GGUF device=gpu / device=cpu（旧字段）及 devices 列表（npu、npu+gpu 等）启动服务并验证 /models + chat。"""
    print(f"\n{'='*60}")
    print("阶段 4: GGUF GPU/CPU/NPU 显式加载回归")
    print(f"{'='*60}")

    devices = args.gguf_devices
    placeholder_model = args.gguf_model or "gpt-oss-20b-GGUF"
    if args.remote:
        for device in devices:
            all_results.append(TestResult(
                name=f"test_gguf_{device}_explicit_load", round_num=1, model_name=f"{placeholder_model} ({device.upper()})",
                passed=False, status_code=0, latency_ms=0,
                detail="远程模式无法临时切换 service_config.json，跳过 GGUF 显式设备加载回归",
                skipped=True
            ))
        return

    gguf_models = [m for m in models if infer_backend(m)[0] == "GGUF"]
    if args.gguf_model:
        gguf_models = [m for m in gguf_models if m == args.gguf_model]
    if not gguf_models:
        for device in devices:
            all_results.append(TestResult(
                name=f"test_gguf_{device}_explicit_load", round_num=1, model_name=f"{placeholder_model} ({device.upper()})",
                passed=False, status_code=0, latency_ms=0,
                detail="未发现 GGUF 模型目录，跳过 GGUF 显式设备加载回归",
                skipped=True
            ))
        return

    try:
        for gguf_model in gguf_models:
            gguf_config_path = Path(args.models) / gguf_model / "config.json"
            if not gguf_config_path.exists():
                for device in devices:
                    all_results.append(TestResult(
                        name=f"test_gguf_{device}_explicit_load", round_num=1, model_name=f"{gguf_model} ({device.upper()})",
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"找不到 GGUF config.json: {gguf_config_path}", skipped=True
                    ))
                continue

            # 显式 backend/device 现在是每个模型自己 config.json 的可选字段（Step 1：并发多模型
            # 托管与 service_config.json 的 models 数组已删除），不再通过 service_config.json 注入。
            original_gguf_config = gguf_config_path.read_bytes()

            def restore_gguf_config():
                gguf_config_path.write_bytes(original_gguf_config)

            for device in devices:
                test_name = f"test_gguf_{device}_explicit_load"
                service_model_name = gguf_model
                result_model_name = f"{gguf_model} ({device.upper()})"
                try:
                    model_config = json.loads(original_gguf_config.decode("utf-8")) if original_gguf_config.strip() else {}
                except json.JSONDecodeError:
                    model_config = {}
                model_config["backend"] = "GGUF"
                requested_list = device.split("+")
                legacy_device = device in ("gpu", "cpu")
                if legacy_device:
                    model_config["device"] = device
                    model_config.pop("devices", None)
                else:
                    model_config["device"] = "cpu" if requested_list == ["cpu"] else "gpu"
                    model_config["devices"] = requested_list
                gguf_config_path.write_text(json.dumps(model_config, ensure_ascii=False, indent=2), encoding="utf-8")

                svc = ServiceManager(args.exe_dir, args.host, args.port)
                svc._log_dir = args.out_dir
                perf = PerfMonitor()
                try:
                    print(f"  启动 GGUF 显式 {device.upper()} 配置: {gguf_model}")
                    start_time = time.time()
                    svc.start(str(gguf_config_path))
                    if not wait_port_open(args.host, args.port, timeout=300, process=svc.process):
                        all_results.append(TestResult(
                            name=test_name, round_num=1, model_name=result_model_name,
                            passed=False, status_code=0, latency_ms=(time.time() - start_time) * 1000,
                            detail="端口 300s 内未可连接"
                        ))
                        continue

                    pid = svc.get_pid()
                    if pid:
                        perf.start(pid)

                    models_resp = requests.get(f"http://{args.host}:{args.port}/models", timeout=30)
                    actual_backend = ""
                    actual_device = ""
                    actual_effective = []
                    if models_resp.status_code == 200:
                        entries = models_resp.json().get("data", [])
                        loaded_entries = [m for m in entries if m.get("is_loaded") and m.get("id") == service_model_name]
                        if loaded_entries:
                            actual_backend = loaded_entries[0].get("backend", "")
                            actual_device = loaded_entries[0].get("device", "")
                            raw_effective = loaded_entries[0].get("devices_effective", "")
                            if isinstance(raw_effective, list):
                                actual_effective = [str(x).lower() for x in raw_effective]
                            elif raw_effective:
                                actual_effective = str(raw_effective).lower().split("+")

                    chat_body = {
                        "model": service_model_name,
                        "messages": [{"role": "user", "content": "Reply with one word: hello"}],
                        "stream": False,
                        "max_tokens": 32,
                    }
                    # 与 APITester.test_chat_non_stream 保持一致的 perf_before/perf_after 采样方式，
                    # 否则这条结果永远没有 CPU/内存数据，报告里的"性能对比"表只能显示 N/A。
                    perf_before = perf.snapshot()
                    chat_start = time.time()
                    chat_resp = requests.post(f"http://{args.host}:{args.port}/v1/chat/completions", json=chat_body, timeout=300)
                    perf_after = perf.snapshot()
                    latency = (time.time() - start_time) * 1000
                    chat_latency = (time.time() - chat_start) * 1000
                    chat_ok = False
                    response_text = ""
                    if chat_resp.status_code == 200:
                        try:
                            choices = chat_resp.json().get("choices", [])
                            response_text = choices[0].get("message", {}).get("content", "") if choices else ""
                            chat_ok = len(response_text) > 0
                        except Exception as e:
                            response_text = f"JSON 解析失败: {e}"

                    backend_ok = actual_backend == "GGUF"
                    device_ok, npu_degraded, fallback_note = evaluate_gguf_device_result(
                        requested_list, actual_device, actual_effective)
                    passed = models_resp.status_code == 200 and chat_resp.status_code == 200 and backend_ok and device_ok and chat_ok
                    detail = (
                        f"requested_device={device}, actual_backend={actual_backend}, actual_device={actual_device}, "
                        f"devices_effective={'+'.join(actual_effective) or '-'}"
                        f"{fallback_note}, /models={models_resp.status_code}, chat={chat_resp.status_code}, "
                        f"chat_latency_ms={chat_latency:.1f}, response_len={len(response_text)}"
                    )
                    all_results.append(TestResult(
                        name=test_name, round_num=1, model_name=result_model_name,
                        passed=passed, status_code=chat_resp.status_code, latency_ms=latency,
                        detail=detail, text_response=response_text, text_prompt=chat_body["messages"][0]["content"],
                        perf_before=perf_before, perf_after=perf_after,
                        response_data={
                            "requested_device": device,
                            "actual_backend": actual_backend,
                            "actual_device": actual_device,
                            "devices_effective": "+".join(actual_effective),
                            "npu_degraded": npu_degraded,
                            "models_status": models_resp.status_code,
                            "chat_status": chat_resp.status_code,
                        }
                    ))
                except (RuntimeError, FileNotFoundError) as e:
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=gguf_model, round_num=1,
                        endpoint=test_name, detail=str(e)
                    ))
                    # GPU 相关的服务启动崩溃仍计入真实失败(crashed=True)，不会因为请求的设备是
                    # gpu 就无条件豁免；命中内存/显存相关关键词时只附加诊断性标注(ignore_reason)，
                    # 不代表已被豁免——崩溃永远是真实问题,正常错误才不会导致连坐。
                    _err_lower = str(e).lower()
                    _mem_hint = any(kw in _err_lower for kw in (
                        "out of memory", "insufficient_memory", "insufficient memory",
                        "cuda", "vram", "allocation failed"
                    ))
                    all_results.append(TestResult(
                        name=test_name, round_num=1, model_name=gguf_model,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"启动失败: {str(e)[:300]}", crashed=True,
                        ignorable=False,
                        ignore_reason=("疑似 GPU 显存/驱动相关(命中内存关键词)，仅作诊断标注，不代表豁免"
                                        if (device == "gpu" and _mem_hint) else "")
                    ))
                except Exception as e:
                    all_results.append(TestResult(
                        name=test_name, round_num=1, model_name=gguf_model,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"测试异常: {e}"
                    ))
                finally:
                    perf_samples = perf.stop()
                    all_perf_samples.extend(perf_samples)
                    print(f"  停止 GGUF 显式 {device.upper()} 服务...")
                    svc.stop()
                    restore_gguf_config()
    finally:
        pass


def run_sampleapp_only_tests(args, models, all_results):
    """SampleApp 专项测试（--suite sampleapp）：只验证 SampleApp.exe（复用
    GenieAPILibrary 引擎的 CLI 客户端），不启动/依赖 GenieAPIService 的 HTTP 服务。

    设计要点（见 .junie/plans/redesign-sampleapp-config-driven-test.md）：
    - 遍历 discover_models 找到的每一个模型（qnn/mnn/GGUF），逐个用 `-c <model>/config.json` 跑一次基本问答；
      SampleApp 每次只加载一个模型（加载前会卸载上一个），所以后一个模型的运行不受前一个影响。
    - 支持 `--model_name a,b` 过滤到指定的一个或若干模型，与 model/mnn/qnn suite 的筛选风格一致。
    - 缺 `SampleApp.exe` → 对每个目标模型各记一条 skipped。
    - 单模型隔离场景下失败即真实失败；仅当命中服务端 MnnVerifier 内存预检查拒绝加载的精确
      文本信号(与 HTTP 端点 failure_reason=insufficient_memory 同一根因)时才归类为 skipped
      (环境资源约束,不是代码缺陷),其它任何原因的失败都不标 ignorable/skipped。
    """
    print(f"\n{'='*60}")
    print("SampleApp 专项测试（--suite sampleapp）")
    print(f"{'='*60}")

    basic_chat_name = "SAMPLEAPP: basic_chat"

    # 按 --model_name（逗号分隔）过滤目标模型；未指定则遍历全部已发现模型。
    target_models = list(models)
    model_filter = getattr(args, "model_name", None)
    if model_filter:
        wanted = {m.strip() for m in model_filter.split(",") if m.strip()}
        target_models = [m for m in models if m in wanted]
        for missing in sorted(wanted - set(models)):
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=missing,
                passed=False, status_code=0, latency_ms=0,
                detail=f"--model_name 指定的模型 '{missing}' 不在已发现模型列表中，跳过", skipped=True
            ))

    if not target_models:
        all_results.append(TestResult(
            name=basic_chat_name, round_num=1, model_name="_sampleapp_",
            passed=False, status_code=0, latency_ms=0,
            detail="未发现任何目标模型（检查 --models / --model_name）", skipped=True
        ))
        return

    sampleapp_exe = Path(args.exe_dir) / "SampleApp.exe"
    if not sampleapp_exe.exists():
        for m in target_models:
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=m,
                passed=False, status_code=0, latency_ms=0,
                detail=f"未找到 {sampleapp_exe}，可能尚未构建该 target，跳过 SampleApp 专项测试",
                skipped=True
            ))
        return

    input_payload = {
        "OptionParams": {"temperature": 0, "top_p": 0.95, "top_k": 40, "n_predict": 512, "n_ctx": 8192},
        "stream": False,
        "messages": [
            {"role": "system", "content": [{"type": "text", "text": "You are a helpful AI assistant."}]},
            {"role": "user", "content": [{"type": "text", "text": "Please introduce yourself briefly."}]}
        ]
    }
    input_path = Path(args.out_dir) / "_sampleapp_input.json"
    input_path.write_text(json.dumps(input_payload, ensure_ascii=False, indent=2), encoding="utf-8")
    prompt_text = input_payload["messages"][1]["content"][0]["text"]

    for model_name in target_models:
        backend, _device = infer_backend(model_name)
        # GGUF 的实际加载设备(gpu/cpu)由服务在运行时决定(先试 gpu,失败退化到 cpu),SampleApp
        # 是独立的单次 CLI 进程,没有 /models 之类的接口可查询实际设备。如果本轮运行(如 full
        # 套件)里其它阶段(阶段2/4/Builder 集成代理)已经为同一个 GGUF 模型打上了设备后缀,这里复用
        # 那个已观测到的设备标签,与既有行合并，避免完备性矩阵/报告里再多出一个孤立裸名行；
        # 若本轮找不到任何已知标签(如单独跑 --suite sampleapp 时)，则保留裸模型名，不影响判定。
        report_model_name = model_name
        if backend == "GGUF":
            existing = next((r.model_name for r in all_results
                              if r.model_name.startswith(f"{model_name} (")), None)
            if existing:
                report_model_name = existing
        config_path = Path(args.models) / model_name / "config.json"
        if not config_path.exists():
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=report_model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"缺失 config.json: {config_path}", skipped=True
            ))
            continue

        print(f"  运行 SampleApp 基本问答: {model_name}（backend={backend}）")
        try:
            start_time = time.time()
            proc = subprocess.run(
                [str(sampleapp_exe), "--config", str(config_path), str(input_path)],
                cwd=args.exe_dir, capture_output=True, text=True, timeout=300,
                encoding="utf-8", errors="replace"
            )
            latency = (time.time() - start_time) * 1000
            # SampleApp.cpp 自身只会主动 return 0/1/2/3；任何其它返回码(尤其是大的负数,对应
            # Windows NTSTATUS)代表进程被 OS 强制终止,是真正的崩溃,必须标记 crashed=True,
            # 不能和"程序自己判断失败后正常退出"混为一谈——否则报告里"崩溃"计数会漏掉这种情况。
            is_crash = _is_sampleapp_crash_exit_code(proc.returncode)
            proc_stdout = proc.stdout or ""
            passed = proc.returncode == 0 and len(proc_stdout.strip()) > 0
            skipped = False
            detail = f"backend={backend}, returncode={proc.returncode}, stdout_len={len(proc_stdout)}"
            if is_crash:
                detail += f", exit_code_hint={_describe_exit_code(proc.returncode)}"
            if not passed:
                detail += f", stderr={(proc.stderr or '')[:300]}"
                if not is_crash and backend == "mnn" and _MNN_INSUFFICIENT_MEMORY_MARKER in proc_stdout:
                    # 与 HTTP 端点 failure_reason=insufficient_memory 同一根因:
                    # MnnVerifier 在进程自身 stdout 日志中直接记录了这段精确文本,
                    # 是环境资源约束,不是代码缺陷,归类为 skipped 而非 failed。
                    skipped = True
                    detail += "; SKIP: 命中 MnnVerifier 内存不足拒绝加载的精确文本信号"
            # 模型缺陷标记(以服务端日志为准)：SampleApp 子进程的 stdout 已完整捕获在
            # proc_stdout 里(不同于 HTTP 场景需要按偏移量扫描共享日志文件),直接对这段
            # 完整文本扫描 [MODEL_DEFECT] 标记即可,天然只属于这一次调用,不会与其它请求混淆。
            defect = _scan_model_defect_text(proc_stdout)
            capability_issue, capability_reason = _capability_issue_from_model_defect(defect)
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=report_model_name,
                passed=passed, status_code=proc.returncode, latency_ms=latency,
                detail=detail, text_response=proc_stdout[:2000], text_prompt=prompt_text,
                crashed=is_crash, skipped=skipped,
                model_capability_issue=capability_issue, model_capability_reason=capability_reason
            ))
        except subprocess.TimeoutExpired as e:
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=report_model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"SampleApp 执行超时: {e}", crashed=True
            ))
        except Exception as e:
            all_results.append(TestResult(
                name=basic_chat_name, round_num=1, model_name=report_model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"测试异常: {e}"
            ))

        # ---- 差异化对照测试：GenieAPIService(HTTP,exe) vs GenieAPILibrary(SampleApp,dll) ----
        # 用途：QNN/多模态请求在 GenieAPIService 侧崩溃时，不能凭猜测把根因归咎于驱动/SDK
        # 或某个宿主特有的问题；这里用与 test_chat_multimodal_openai_style 完全相同的 OpenAI
        # 数组风格 content(文本+图片 data URI)构造输入，经 SampleApp.cpp 里"整段 JSON 原样
        # dump 后传给 api_Generate"的转发路径(见 SampleApp.cpp 第 271-337 行)，喂给同一个
        # ModelInputBuilder::ProcessArray 引擎代码——与 HTTP 端点是同一份共享源码，只是宿主
        # 不同(exe 用 SERVICE_SOURCES 编译，dll 额外链接 GenieAPILibrary.cpp 胶水层)。
        # 只要本轮任何 suite 已经跑过该模型的多模态用例(阶段2/full)，两边用的都是同一批
        # data_dir 素材池，具备可比性；单独跑 --suite sampleapp 时同样会独立抽取一次素材。
        # 判定规则：
        #   - 两边都崩溃 → 是共享引擎代码本身的真实 bug，与宿主无关；
        #   - 只有一边崩溃 → 该次崩溃与某个宿主特有的路径相关(而不是驱动/SDK)，需要针对性排查；
        #   - 两边都不崩溃 → 这次未复现，不代表问题不存在(崩溃可能是非确定性的)。
        # 报告里不在这里下结论，只如实记录 crashed/exit_code_hint，由后续汇总环节比对两边结果。
        multimodal_image_name = "SAMPLEAPP: multimodal_image (vs GenieAPIService 对照)"
        modality = detect_modality(model_name)
        if "image" in modality:
            image_path, image_err = _pick_random_asset_file(args.data_dir, "img", {".jpg", ".jpeg", ".png"})
            if image_path is None:
                all_results.append(TestResult(
                    name=multimodal_image_name, round_num=1, model_name=report_model_name,
                    passed=False, status_code=0, latency_ms=0,
                    detail=f"素材缺失: {image_err}",
                    skipped=True, ignorable=True, ignore_reason="data_dir 下 img 素材缺失"
                ))
            else:
                ext = image_path.suffix.lower().lstrip(".")
                if ext == "jpg":
                    ext = "jpeg"
                image_b64 = base64.b64encode(image_path.read_bytes()).decode("ascii")
                mm_payload = {
                    "OptionParams": {"temperature": 0, "top_p": 0.95, "top_k": 40, "n_predict": 512, "n_ctx": 8192},
                    "stream": False,
                    "messages": [
                        {"role": "user", "content": [
                            {"type": "text", "text": random.choice(MULTIMODAL_PROMPTS)},
                            {"type": "image_url", "image_url": {"url": f"data:image/{ext};base64,{image_b64}"}}
                        ]}
                    ]
                }
                mm_input_path = Path(args.out_dir) / f"_sampleapp_multimodal_input_{model_name.replace('/', '_')}.json"
                mm_input_path.write_text(json.dumps(mm_payload, ensure_ascii=False, indent=2), encoding="utf-8")
                print(f"  运行 SampleApp 多模态对照测试: {model_name}（image={image_path.name}）")
                try:
                    mm_start = time.time()
                    mm_proc = subprocess.run(
                        [str(sampleapp_exe), "--config", str(config_path), str(mm_input_path)],
                        cwd=args.exe_dir, capture_output=True, text=True, timeout=300,
                        encoding="utf-8", errors="replace"
                    )
                    mm_latency = (time.time() - mm_start) * 1000
                    mm_is_crash = _is_sampleapp_crash_exit_code(mm_proc.returncode)
                    mm_stdout = mm_proc.stdout or ""
                    mm_passed = mm_proc.returncode == 0 and len(mm_stdout.strip()) > 0
                    mm_detail = (f"backend={backend}, image={image_path.name}, "
                                  f"returncode={mm_proc.returncode}, stdout_len={len(mm_stdout)}")
                    if mm_is_crash:
                        mm_detail += f", exit_code_hint={_describe_exit_code(mm_proc.returncode)}"
                    if not mm_passed:
                        mm_detail += f", stderr={(mm_proc.stderr or '')[:300]}"
                    mm_defect = _scan_model_defect_text(mm_stdout)
                    mm_capability_issue, mm_capability_reason = _capability_issue_from_model_defect(mm_defect)
                    all_results.append(TestResult(
                        name=multimodal_image_name, round_num=1, model_name=report_model_name,
                        passed=mm_passed, status_code=mm_proc.returncode, latency_ms=mm_latency,
                        detail=mm_detail, text_response=mm_stdout[:2000],
                        text_prompt=mm_payload["messages"][0]["content"][0]["text"],
                        crashed=mm_is_crash,
                        model_capability_issue=mm_capability_issue, model_capability_reason=mm_capability_reason
                    ))
                except subprocess.TimeoutExpired as e:
                    all_results.append(TestResult(
                        name=multimodal_image_name, round_num=1, model_name=report_model_name,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"SampleApp 多模态对照测试执行超时: image={image_path.name}, {e}", crashed=True
                    ))
                except Exception as e:
                    all_results.append(TestResult(
                        name=multimodal_image_name, round_num=1, model_name=report_model_name,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"测试异常: image={image_path.name}, {e}"
                    ))


def run_graceful_shutdown_tests(args, models, all_results, all_crash_events):
    """验证三种后端在推理请求进行中被终止时，能走既有的优雅关闭路径正常退出，而不是被
    Windows 判定为异常崩溃（如 STATUS_ACCESS_VIOLATION 等 NTSTATUS 崩溃特征码）。每种
    后端各选一个已发现的代表模型，用 CTRL_BREAK_EVENT（Windows 上唯一能只定向到本进程、
    不影响同控制台其它进程的信号；服务已注册 SetConsoleCtrlHandler 复用与 Ctrl+C 相同的
    ServiceStop() 路径）在其正在处理一次长耗时流式推理请求期间终止服务进程。仅支持本地
    模式（需要直接控制服务进程发送信号），远程模式/非 Windows 环境下精确跳过。"""
    print(f"\n{'='*60}")
    print("阶段: 推理中终止进程 → 优雅退出验证")
    print(f"{'='*60}")

    test_name = "GRACEFUL_SHUTDOWN: terminate during inference"

    if args.remote:
        all_results.append(TestResult(
            name=test_name, round_num=1, model_name="_graceful_shutdown_",
            passed=False, status_code=0, latency_ms=0,
            detail="远程模式无法直接控制服务进程发送终止信号，跳过优雅关闭验证", skipped=True
        ))
        return
    if os.name != "nt" or not hasattr(signal, "CTRL_BREAK_EVENT"):
        all_results.append(TestResult(
            name=test_name, round_num=1, model_name="_graceful_shutdown_",
            passed=False, status_code=0, latency_ms=0,
            detail="当前环境不支持 CTRL_BREAK_EVENT（非 Windows），跳过优雅关闭验证", skipped=True
        ))
        return

    targets = {}
    for backend_key in ("qnn", "GGUF", "mnn"):
        candidates = sorted(m for m in models if infer_backend(m)[0] == backend_key)
        if candidates:
            targets[backend_key] = candidates[0]

    for backend_key in ("qnn", "GGUF", "mnn"):
        model_name = targets.get(backend_key)
        result_model_name = f"_graceful_shutdown_ ({backend_key})"
        if not model_name:
            all_results.append(TestResult(
                name=test_name, round_num=1, model_name=result_model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"未发现 {backend_key} 后端模型，跳过该后端的优雅关闭验证", skipped=True
            ))
            continue

        config_path = Path(args.models) / model_name / "config.json"
        if not config_path.exists():
            all_results.append(TestResult(
                name=test_name, round_num=1, model_name=result_model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"缺失 config.json: {config_path}", skipped=True
            ))
            continue

        # 三个后端在本函数内连续重启,上一个后端的进程刚被 _force_kill() 结束时,其监听端口
        # 可能尚处于 TIME_WAIT/延迟释放阶段;不等待就直接 start() 会命中 isPortAvailable()
        # 判定为占用、打印"service already exist."并以 exit_code=0 立即退出，被误判为崩溃。
        wait_port_closed(args.host, args.port, timeout=15)
        svc = ServiceManager(args.exe_dir, args.host, args.port)
        svc._log_dir = args.out_dir
        start_time = time.time()
        try:
            print(f"  [{backend_key}] 启动服务用于优雅关闭验证: {model_name}")
            svc.start(str(config_path))
            if not wait_port_open(args.host, args.port, timeout=180, process=svc.process):
                all_results.append(TestResult(
                    name=test_name, round_num=1, model_name=result_model_name,
                    passed=False, status_code=0, latency_ms=(time.time() - start_time) * 1000,
                    detail="端口 180s 内未可连接", skipped=True
                ))
                continue

            pid = svc.process.pid
            chat_body = {
                "model": model_name,
                "messages": [{"role": "user", "content":
                    "Write a very long, detailed step-by-step essay about the history of computing, "
                    "at least 3000 words."}],
                "stream": True,
                "max_tokens": 2048,
            }

            first_chunk_event = threading.Event()

            def _do_stream():
                try:
                    with requests.post(f"http://{args.host}:{args.port}/v1/chat/completions",
                                        json=chat_body, stream=True, timeout=120) as r:
                        for line in r.iter_lines():
                            if line:
                                first_chunk_event.set()
                                break
                        for _ in r.iter_lines():  # 继续消费剩余流,直到进程被终止打断连接
                            pass
                except Exception:
                    pass  # 进程即将被终止,连接异常是预期结果,这里只负责驱动请求,不关心具体异常

            stream_thread = threading.Thread(target=_do_stream, daemon=True)
            stream_thread.start()

            if not first_chunk_event.wait(timeout=60):
                all_results.append(TestResult(
                    name=test_name, round_num=1, model_name=result_model_name,
                    passed=False, status_code=0, latency_ms=(time.time() - start_time) * 1000,
                    detail="60s 内未收到推理流式响应的第一个数据块，无法确认推理是否已开始", skipped=True
                ))
                continue

            time.sleep(1.5)  # 确保终止信号发出时推理正在进行中,而不是刚开始加载/已经结束
            print(f"  [{backend_key}] 向 PID {pid} 发送 CTRL_BREAK_EVENT（推理进行中）...")
            os.kill(pid, signal.CTRL_BREAK_EVENT)

            try:
                exit_code = svc.process.wait(timeout=30)
            except subprocess.TimeoutExpired:
                exit_code = None
            stream_thread.join(timeout=5)
            latency = (time.time() - start_time) * 1000

            if exit_code is None:
                all_results.append(TestResult(
                    name=test_name, round_num=1, model_name=result_model_name,
                    passed=False, status_code=0, latency_ms=latency,
                    detail="推理进行中发送终止信号后 30s 内未退出（挂起，非崩溃但同样是需要关注的真实缺陷）",
                    crashed=True, ignorable=False
                ))
                all_crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(), model_name=model_name, round_num=1,
                    endpoint=test_name, detail="终止信号发出后 30s 内进程未退出（挂起）",
                    log_tail=svc.read_log_tail(svc._stderr_log, 50)
                ))
                continue

            log_tail = svc.read_log_tail(svc._stdout_log, 80)
            log_tail_lower = log_tail.lower()
            graceful_marker_present = "service stopped successfully" in log_tail_lower
            watchdog_triggered = (exit_code == _SHUTDOWN_WATCHDOG_EXIT_CODE or
                                   _SHUTDOWN_WATCHDOG_LOG_MARKER in log_tail_lower)
            crash_hint = _WINDOWS_EXIT_CODE_HINTS.get(exit_code)
            if watchdog_triggered:
                # 看门狗兜底强制终止：底层推理调用未在阈值内响应 ModelManager::UnloadModel()
                # 发出的 Stop() 信号，进程被主动强制终止而不是无限期挂起——这是已知的兜底
                # 路径，不是崩溃（不落在 _WINDOWS_EXIT_CODE_HINTS 崩溃特征码表内），也没有走完
                # 常规的优雅关闭日志，因此单独归类：不算 passed（未能优雅关闭），也不算 crashed。
                all_results.append(TestResult(
                    name=test_name, round_num=1, model_name=result_model_name,
                    passed=False, status_code=exit_code, latency_ms=latency,
                    detail=(f"backend={backend_key}, model={model_name}, "
                            f"exit_code={_describe_exit_code(exit_code)}, "
                            f"看门狗兜底强制终止(非崩溃): 底层推理调用未在观察窗口内响应停止信号"),
                    crashed=False, ignorable=False,
                    response_data={"backend": backend_key, "exit_code": exit_code, "watchdog_forced_exit": True}
                ))
                continue
            is_graceful = crash_hint is None and graceful_marker_present
            detail = (f"backend={backend_key}, model={model_name}, exit_code={_describe_exit_code(exit_code)}, "
                      f"graceful_shutdown_log_marker={'found' if graceful_marker_present else 'NOT found'}")
            all_results.append(TestResult(
                name=test_name, round_num=1, model_name=result_model_name,
                passed=is_graceful, status_code=exit_code, latency_ms=latency,
                detail=detail, crashed=(crash_hint is not None), ignorable=False,
                response_data={"backend": backend_key, "exit_code": exit_code,
                                "exit_code_hint": crash_hint or "", "graceful_marker": graceful_marker_present}
            ))
            if crash_hint is not None:
                all_crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(), model_name=model_name, round_num=1,
                    endpoint=test_name,
                    detail=f"终止信号发出后进程以崩溃特征退出: {_describe_exit_code(exit_code)}",
                    log_tail=log_tail
                ))
        except (RuntimeError, FileNotFoundError) as e:
            all_results.append(TestResult(
                name=test_name, round_num=1, model_name=result_model_name,
                passed=False, status_code=0, latency_ms=(time.time() - start_time) * 1000,
                detail=f"启动失败: {str(e)[:300]}", crashed=True, ignorable=False
            ))
        except Exception as e:
            all_results.append(TestResult(
                name=test_name, round_num=1, model_name=result_model_name,
                passed=False, status_code=0, latency_ms=(time.time() - start_time) * 1000,
                detail=f"测试异常: {e}"
            ))
        finally:
            svc._force_kill()


def _finalize_and_exit(all_results, all_perf_samples, all_crash_events, out_dir, remote_mode, suite_name, cmdline=""):
    """汇总统计 + 生成全部报告 + 计算退出码。所有 suite 收尾都走这一个函数，避免重复代码。"""
    print(f"\n{'='*60}")
    print("生成报告...")
    print(f"{'='*60}")
    ReportGenerator.generate_json(all_results, all_perf_samples, all_crash_events, str(out_dir))
    ReportGenerator.generate_summary_html(all_results, all_perf_samples, all_crash_events, str(out_dir),
                                           remote_mode=remote_mode, suite_name=suite_name, cmdline=cmdline)
    ReportGenerator.generate_model_reports(all_results, all_perf_samples, all_crash_events, str(out_dir),
                                            remote_mode=remote_mode, cmdline=cmdline)
    ReportGenerator.generate_conversations(all_results, str(out_dir))

    # 与 generate_summary_html() 的 summary_all 用同一套互斥分类优先级（SKIP > CRASHED > PASSED > FAILED），
    # 避免同一条 TestResult 被多个桶重复计数导致 passed+failed+crashed+skipped != total。
    total = len(all_results)
    passed = failed = crashed = skipped = 0
    for r in all_results:
        if r.skipped:
            skipped += 1
        elif r.crashed:
            crashed += 1
        elif r.passed:
            passed += 1
        else:
            failed += 1
    print(f"\n{'='*60}")
    print(f"测试完成: {passed}/{total} 通过, {failed} 失败, {crashed} 崩溃, {skipped} 跳过")
    print(f"{'='*60}")
    sys.exit(0 if failed == 0 and crashed == 0 else 1)


def _run_sampleapp_suite(args, models, remote_mode, out_dir):
    """--suite sampleapp：只验证 SampleApp.exe，不涉及 GenieAPIService HTTP 全量回归。"""
    all_results = []
    run_sampleapp_only_tests(args, models, all_results)
    return all_results, [], []


def _run_gguf_suite(args, models, remote_mode, out_dir):
    """--suite gguf：只运行 GGUF GPU/CPU 显式加载回归。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []
    run_gguf_explicit_load_regressions(args, models, all_results, all_crash_events, all_perf_samples)
    return all_results, all_perf_samples, all_crash_events


def _run_graceful_shutdown_suite(args, models, remote_mode, out_dir):
    """--suite graceful_shutdown：只运行"推理中终止进程 → 优雅退出验证"。"""
    all_results = []
    all_crash_events = []
    run_graceful_shutdown_tests(args, models, all_results, all_crash_events)
    return all_results, [], all_crash_events


def _run_full_suite(args, models, remote_mode, out_dir):
    """--suite full：阶段1通用接口 → 阶段2逐模型 → 阶段3多模型并发 → 阶段4 GGUF 显式加载 →
    阶段5 Builder 集成代理 → 阶段6 SampleApp。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []

    # ===== 阶段 1：模型无关的通用接口测试（只测一次） =====
    print(f"\n{'='*60}")
    print("阶段 1: 通用接口测试（模型无关）")
    print(f"{'='*60}")
    stage1_startup_failed = False
    if remote_mode:
        svc_global = RemoteServiceManager(args.host, args.port)
    else:
        # 本地模式：用第一个模型的 config 启动服务
        config_path = Path(args.models) / models[0] / "config.json"
        svc_global = ServiceManager(args.exe_dir, args.host, args.port)
        svc_global._log_dir = args.out_dir
        try:
            svc_global.start(str(config_path))
            # 等服务进程发完初始化并绑定 TCP 端口 (轮询 connect,避免 ConnectionRefused)
            # 8B 模型 QNN 初始化可能 ≪ 60s,这里给 120s 余裕。
            # 同时把 Popen 传进去,子进程秒退能立刻发现,而不是空等 120 秒。
            print("  等待端口可连接...")
            if not wait_port_open(args.host, args.port, timeout=120, process=svc_global.process):
                print("  ⚠ 端口 120s 内未可连接,仍然尝试进入测试")
            else:
                print("  ✓ 端口已可连接")
        except (RuntimeError, FileNotFoundError) as e:
            # 服务启动失败 (秒退 / 找不到 exe / 端口轮询期间发现进程已死)
            # 记录到 crash_events,跳过阶段 1 的测试,继续进入阶段 2 (后面的模型也会各自重试启动)。
            print(f"  ✗ 服务启动失败: {e}")
            stage1_startup_failed = True
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name="_global_", round_num=1,
                endpoint="SERVICE_STARTUP", detail=str(e)
            ))
            all_results.append(TestResult(
                name="服务启动 (阶段 1)", round_num=1, model_name="_global_",
                passed=False, status_code=0, latency_ms=0,
                detail=f"启动失败: {str(e)[:300]}",
                crashed=True
            ))

    if not stage1_startup_failed:
        perf_global = PerfMonitor()
        global_tester = APITester(args.host, args.port, svc_global, perf_global, "_global_", total_rounds=1)
        global_results = global_tester.run_global_tests()
        all_results.extend(global_results)

        # 通用接口测试的最后一项: /servicestop (会让服务进程退出,所以放最后)
        # remote_mode 下也调用,但要求调用方确认/接受服务会被关闭。
        print(f"    测试 POST /servicestop ... ", end="", flush=True)
        stop_result = global_tester.test_servicestop(1)
        status = "✓ PASS" if stop_result.passed else ("✗ CRASH" if stop_result.crashed else "✗ FAIL")
        print(f"{status} ({stop_result.latency_ms:.0f}ms)")
        all_results.append(stop_result)

        if not remote_mode:
            # /servicestop 已经让进程退出了,这里 stop() 多半是 no-op,
            # 但保留一次确认调用以释放本地资源(关闭日志句柄等)。
            svc_global.stop()
    else:
        # 启动失败是最严重的信号之一：阶段 1 的通用接口测试统统未能真正执行，但这不是
        # "环境不适用/设计不支持"这类合理跳过场景，而是服务本身出了问题——统一标记为
        # crashed=True（而不是 skipped=True），确保计入 failed/crashed 统计和退出码，
        # 不会被 _finalize_and_exit 的统计口径悄悄漏掉。
        for ep in ["GET /", "GET /models", "GET /v1/models", "POST /servicestop"]:
            all_results.append(TestResult(
                name=ep, round_num=1, model_name="_global_",
                passed=False, status_code=0, latency_ms=0,
                detail="服务未能启动，通用接口测试未能真正执行", crashed=True
            ))

    # ===== 阶段 2：每个模型的完整生命周期测试 =====
    # 复用 _run_model_suite（不带 --model_name 过滤，等价于对全部已发现模型执行），
    # 保证 full suite 与独立的 --suite model 在阶段2上完全一致，不重复维护两套逻辑。
    stage2_results, stage2_perf, stage2_crashes = _run_model_suite(args, models, remote_mode, out_dir)
    all_results.extend(stage2_results)
    all_perf_samples.extend(stage2_perf)
    all_crash_events.extend(stage2_crashes)

    # ===== 阶段 3：多模型并发加载与路由测试 =====
    # 复用 _run_multi_model_suite，同理保证 full suite 与独立的 --suite multi_model 行为一致。
    stage3_results, stage3_perf, stage3_crashes = _run_multi_model_suite(args, models, remote_mode, out_dir)
    all_results.extend(stage3_results)
    all_perf_samples.extend(stage3_perf)
    all_crash_events.extend(stage3_crashes)

    run_gguf_explicit_load_regressions(args, models, all_results, all_crash_events, all_perf_samples)

    # 紧跟 GGUF 显式加载回归之后：-n -1 vs -n 30 差异化自验证矩阵（不经 Builder，直接启动裸
    # GenieAPIService.exe，验证历史管理/系统提示词优化/工具定义优化/长文本摘要 4 项行为
    # 差异确实按预期互斥发生）。
    run_numresponse_stateless_mode_regressions(args, models, all_results, all_crash_events, all_perf_samples)

    # ===== 阶段 6：SampleApp 专项测试 =====
    # SampleApp 用户明确要求纳入 full 套件的默认执行范围（此前完全独立，导致完备性矩阵的
    # SampleApp 列在 full 下永远显示"未运行本轮"）。复用 --suite sampleapp 同一个实现，
    # 不重复维护第二套逻辑；不传 --model_name 过滤时等价于遍历全部已发现模型。
    run_sampleapp_only_tests(args, models, all_results)

    # ===== 阶段 7：推理中终止进程 → 优雅退出验证 =====
    run_graceful_shutdown_tests(args, models, all_results, all_crash_events)

    return all_results, all_perf_samples, all_crash_events


def _run_model_suite(args, models, remote_mode, out_dir):
    """--suite model（也被 full suite 阶段2复用）：对目标模型执行完整生命周期测试。
    未指定 --model_name 时测试全部已发现模型；指定时（逗号分隔）仅测试匹配的模型。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []

    target_models = models
    model_filter = getattr(args, "model_name", None)
    if model_filter:
        wanted = {m.strip() for m in model_filter.split(",") if m.strip()}
        target_models = [m for m in models if m in wanted]
        for missing in sorted(wanted - set(models)):
            all_results.append(TestResult(
                name="MODEL_FILTER", round_num=1, model_name=missing,
                passed=False, status_code=0, latency_ms=0,
                detail=f"--model_name 指定的模型 '{missing}' 不在已发现模型列表中，跳过", skipped=True
            ))

    for model_name in target_models:
        print(f"\n{'='*60}")
        print(f"阶段 2: 模型测试 - {model_name}")
        print(f"{'='*60}")

        if remote_mode:
            svc = RemoteServiceManager(args.host, args.port)
        else:
            config_path = Path(args.models) / model_name / "config.json"
            svc = ServiceManager(args.exe_dir, args.host, args.port)
            svc._log_dir = args.out_dir
        perf = PerfMonitor()

        try:
            if remote_mode:
                # 远程模式：检查服务是否可达（仅此处做一次实际连通性检查）
                print(f"  检查远程服务...")
                if not svc.check_connectivity(timeout=10):
                    print(f"  ✗ 远程服务不可达，跳过模型 {model_name}")
                    for rnd in range(1, args.rounds + 1):
                        all_results.append(TestResult(
                            name="SERVICE_CHECK", round_num=rnd, model_name=model_name,
                            passed=False, status_code=0, latency_ms=0,
                            detail="远程服务不可达", skipped=True
                        ))
                    continue
                print(f"  ✓ 远程服务可达")
            else:
                print(f"  启动服务...")
                try:
                    svc.start(str(config_path))
                except (RuntimeError, FileNotFoundError) as e:
                    # 服务启动失败 (秒退 / 找不到 exe)
                    # 记录一条 SERVICE_STARTUP 崩溃事件 + 每一轮一条 skipped TestResult,
                    # 然后 continue 到下一个模型 (不要让整个脚本崩溃)。
                    print(f"  ✗ 服务启动失败: {e}")
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=model_name, round_num=0,
                        endpoint="SERVICE_STARTUP", detail=str(e)
                    ))
                    # 每个模型都是全新的 ServiceManager/进程,不存在"MNN OOM 级联"的可能;
                    # 按分类规则判定后恒为真实错误(ignorable=False),不再用"gguf/mnn/gpu"关键字统一豁免。
                    ignorable, ignore_reason, classify_detail = _classify_process_down(svc, model_name)
                    for rnd in range(1, args.rounds + 1):
                        all_results.append(TestResult(
                            name="服务启动", round_num=rnd, model_name=model_name,
                            passed=False, status_code=0, latency_ms=0,
                            detail=f"启动失败: {str(e)[:300]}; {classify_detail}",
                            crashed=True,
                            ignorable=ignorable,
                            ignore_reason=ignore_reason
                        ))
                    continue
                # 轮询 TCP 端口,避免第一个请求碍在 ConnectionRefused 上;
                # 把 Popen 传进去,子进程秒退能立刻被发现。
                print(f"  等待端口可连接...")
                try:
                    if not wait_port_open(args.host, args.port, timeout=120, process=svc.process):
                        print(f"  ⚠ 端口 120s 内未可连接,仍然尝试进入测试")
                    else:
                        print(f"  ✓ 端口已可连接,进入测试")
                except RuntimeError as e:
                    # wait_port_open 期间发现子进程退出 — 同上记录并 continue
                    print(f"  ✗ 服务启动后秒退: {e}")
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=model_name, round_num=0,
                        endpoint="SERVICE_STARTUP", detail=str(e)
                    ))
                    ignorable, ignore_reason, classify_detail = _classify_process_down(svc, model_name)
                    for rnd in range(1, args.rounds + 1):
                        all_results.append(TestResult(
                            name="服务启动", round_num=rnd, model_name=model_name,
                            passed=False, status_code=0, latency_ms=0,
                            detail=f"启动失败: {str(e)[:300]}; {classify_detail}",
                            crashed=True,
                            ignorable=ignorable,
                            ignore_reason=ignore_reason
                        ))
                    continue

            # 启动性能采集
            pid = svc.get_pid()
            if pid:
                perf.start(pid)

            # GGUF 模型未在 config.json 里显式指定 device 时,服务会自己选(先试 gpu,失败退化
            # 到 cpu)——这条常规生命周期测试用的正是这个"隐式"设备。如果不把实际设备打到报告
            # 用的 model_name 上,报告/完备性矩阵里就会出现一个裸模型名的行,与阶段4显式加载回归
            # 产生的 "<model> (CPU)"/"<model> (GPU)" 两行并列,变成同一个模型被拆成 3 行。
            # 这里查一次 /models 拿到真实 device,把本模型本轮的全部结果标签都改成设备后缀形式,
            # 使其自然并入阶段4已经使用的同一个设备分桶。只对 GGUF 生效——QNN/MNN 的设备
            # (npu/cpu)是固定的,没有这种歧义,不需要打标签。
            report_model_name = model_name
            if infer_backend(model_name)[0] == "GGUF":
                try:
                    models_resp = requests.get(f"http://{args.host}:{args.port}/models", timeout=10)
                    if models_resp.status_code == 200:
                        entries = models_resp.json().get("data", [])
                        loaded = [m for m in entries if m.get("is_loaded") and m.get("id") == model_name]
                        if loaded and loaded[0].get("device"):
                            report_model_name = f"{model_name} ({loaded[0]['device'].upper()})"
                except Exception:
                    pass  # 探测失败时保留裸模型名,不影响测试本身,只是报告展示上退化为旧行为

            # 多轮测试（不含多模态用例，也不做收尾；多模态轮次与收尾单独处理，见下方）
            oom_triggered = False
            for rnd in range(1, args.rounds + 1):
                print(f"\n  --- 第 {rnd}/{args.rounds} 轮 ---")
                tester = APITester(args.host, args.port, svc, perf, model_name, total_rounds=args.rounds,
                                   data_dir=args.data_dir, all_models=models, multimodal_rounds=args.multimodal_rounds,
                                   exe_dir=args.exe_dir if not remote_mode else None)
                round_results = tester.run_all(rnd, include_final_cleanup=False)
                if report_model_name != model_name:
                    for r in round_results:
                        r.model_name = report_model_name
                all_results.extend(round_results)
                all_crash_events.extend(tester.crash_events)
                # MNN OOM 崩溃后已自动重启：跳过该模型本轮剩余测试，继续下一个模型
                if any(getattr(r, "auto_restarted", False) for r in round_results):
                    print(f"  ⚠ 检测到 MNN OOM 崩溃并已自动重启，跳过 {model_name} 剩余轮次")
                    oom_triggered = True
                    break

            if not oom_triggered:
                # 多模态轮次（由 --multimodal_rounds 驱动，与 --rounds 完全解耦）与收尾
                # （stop/clear/unload）必须在模型真正卸载前完成，且不应在已确认 MNN OOM
                # 自动重启的模型上再额外触发一轮请求。
                mm_tester = APITester(args.host, args.port, svc, perf, model_name, total_rounds=args.rounds,
                                      data_dir=args.data_dir, all_models=models, multimodal_rounds=args.multimodal_rounds)
                mm_results = mm_tester.run_multimodal_rounds()
                mm_results.extend(mm_tester.run_final_cleanup(args.rounds))
                if report_model_name != model_name:
                    for r in mm_results:
                        r.model_name = report_model_name
                all_results.extend(mm_results)
                all_crash_events.extend(mm_tester.crash_events)

            # 停止性能采集
            perf_samples = perf.stop()
            all_perf_samples.extend(perf_samples)

        except Exception as e:
            # 未被内层捕获的异常：不能只记 CrashEvent 而不产生对应的 TestResult，否则
            # _finalize_and_exit 的 failed/crashed 统计和退出码完全看不到这次异常
            # （all_crash_events 不参与那个判定）。这里补一条 crashed=True 的 TestResult，
            # 与已有的 CrashEvent 追加保持一致，确保异常被无条件计入统计。
            print(f"  ✗ 测试异常: {e}")
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name=model_name, round_num=0,
                endpoint="GLOBAL", detail=str(e)
            ))
            all_results.append(TestResult(
                name="GLOBAL", round_num=0, model_name=model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"套件级未捕获异常: {e}", crashed=True
            ))
        finally:
            if not remote_mode:
                print(f"  停止服务...")
                svc.stop()

    return all_results, all_perf_samples, all_crash_events


def _run_multimodal_suite(args, models, remote_mode, out_dir):
    """--suite multimodal：自动筛选支持多模态的模型，只运行多模态相关用例，跳过其余通用接口测试。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []

    multimodal_models = [m for m in models if detect_modality(m)]
    if not multimodal_models:
        all_results.append(TestResult(
            name="MULTIMODAL_FILTER", round_num=1, model_name="_multimodal_",
            passed=False, status_code=0, latency_ms=0,
            detail="未发现任何支持多模态的模型（detect_modality 返回空集合），跳过 multimodal suite",
            skipped=True
        ))
        return all_results, all_perf_samples, all_crash_events

    for model_name in multimodal_models:
        print(f"\n{'='*60}")
        print(f"多模态测试 - {model_name}")
        print(f"{'='*60}")

        if remote_mode:
            svc = RemoteServiceManager(args.host, args.port)
        else:
            config_path = Path(args.models) / model_name / "config.json"
            svc = ServiceManager(args.exe_dir, args.host, args.port)
            svc._log_dir = args.out_dir
        perf = PerfMonitor()

        try:
            if remote_mode:
                print(f"  检查远程服务...")
                if not svc.check_connectivity(timeout=10):
                    print(f"  ✗ 远程服务不可达，跳过模型 {model_name}")
                    all_results.append(TestResult(
                        name="SERVICE_CHECK", round_num=1, model_name=model_name,
                        passed=False, status_code=0, latency_ms=0,
                        detail="远程服务不可达", skipped=True
                    ))
                    continue
                print(f"  ✓ 远程服务可达")
            else:
                print(f"  启动服务...")
                try:
                    svc.start(str(config_path))
                except (RuntimeError, FileNotFoundError) as e:
                    print(f"  ✗ 服务启动失败: {e}")
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=model_name, round_num=0,
                        endpoint="SERVICE_STARTUP", detail=str(e)
                    ))
                    all_results.append(TestResult(
                        name="服务启动", round_num=1, model_name=model_name,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"启动失败: {str(e)[:300]}", crashed=True
                    ))
                    continue
                print(f"  等待端口可连接...")
                try:
                    if not wait_port_open(args.host, args.port, timeout=120, process=svc.process):
                        print(f"  ⚠ 端口 120s 内未可连接,仍然尝试进入测试")
                    else:
                        print(f"  ✓ 端口已可连接,进入测试")
                except RuntimeError as e:
                    print(f"  ✗ 服务启动后秒退: {e}")
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(),
                        model_name=model_name, round_num=0,
                        endpoint="SERVICE_STARTUP", detail=str(e)
                    ))
                    all_results.append(TestResult(
                        name="服务启动", round_num=1, model_name=model_name,
                        passed=False, status_code=0, latency_ms=0,
                        detail=f"启动失败: {str(e)[:300]}", crashed=True
                    ))
                    continue

            pid = svc.get_pid()
            if pid:
                perf.start(pid)

            # --suite multimodal 完全由 --multimodal_rounds 驱动（不再跟 --rounds 绑定），
            # 复用 APITester.run_multimodal_rounds() 与逐模型标准生命周期测试同一套用例实现。
            tester = APITester(args.host, args.port, svc, perf, model_name, total_rounds=args.rounds,
                               data_dir=args.data_dir, all_models=models, multimodal_rounds=args.multimodal_rounds)
            all_results.extend(tester.run_multimodal_rounds())
            all_crash_events.extend(tester.crash_events)

            perf_samples = perf.stop()
            all_perf_samples.extend(perf_samples)

        except Exception as e:
            # 与 _run_model_suite 相同的规范：异常必须同时产生 TestResult(crashed=True)
            # 和 CrashEvent，才能被 _finalize_and_exit 的统计口径和退出码捕捉到。
            print(f"  ✗ 测试异常: {e}")
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name=model_name, round_num=0,
                endpoint="GLOBAL", detail=str(e)
            ))
            all_results.append(TestResult(
                name="GLOBAL", round_num=0, model_name=model_name,
                passed=False, status_code=0, latency_ms=0,
                detail=f"套件级未捕获异常: {e}", crashed=True
            ))
        finally:
            if not remote_mode:
                print(f"  停止服务...")
                svc.stop()

    return all_results, all_perf_samples, all_crash_events


def _run_multi_model_suite(args, models, remote_mode, out_dir):
    """--suite multi_model（也被 full suite 阶段3复用）：多模型并发加载与路由测试。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []

    # 使用第一个可用（非崩溃）模型的 config 启动服务
    # 优先选择 QNN 模型（最稳定），避免使用 GGUF/MNN 模型（可能因内存不足崩溃）
    print(f"\n{'='*60}")
    print("阶段 3: 多模型并发加载与路由测试")
    print(f"{'='*60}")
    stage3_startup_failed = False

    # 选择阶段 3 启动用的模型：优先选 QNN 模型（不含 GGUF/MNN 关键字）。本地模式下
    # 同一设备如果有多个候选，进一步优先选磁盘占用（权重文件大小）最小的那个——道理见
    # 下方 models_by_device 的注释：入口模型越轻，留给后续动态加载的 GGUF/MNN 的可用
    # 内存越多，"多类型同时加载"这组测试才更有机会被真正测到。
    def _pick_stage3_model(model_list):
        preferred = [m for m in model_list
                     if "gguf" not in m.lower() and "mnn" not in m.lower()]
        if not preferred:
            return model_list[0]
        if remote_mode:
            return preferred[0]
        return min(preferred, key=lambda m: _estimate_model_dir_size_bytes(args.models, m))

    # 构建 npu/gpu(GGUF)/cpu(MNN) 三设备各一个模型的映射，驱动
    # ensure_multi_backend_loaded 主动触发三后端同时驻留。
    #
    # 同一设备如果有多个候选模型，不再简单取"目录名字母序中第一个发现的"，而是（本地模式下）
    # 优先选择磁盘占用（权重文件大小）最小的那个——这样能最大化"多类型同时加载"这组测试
    # 实际被有效验证到的概率：如果任由字母序碰巧选中一个偏大的模型占用更多内存，会连带
    # 压缩其它设备的可用内存，让共存/两两降级验证更容易因资源不足被跳过而没有真正测到东西，
    # 也更容易让内存实际吃紧的组合从"可能可以两两共存"变成"必然被内存挤没"。远程模式下
    # 不知道模型文件在对端机器上的实际大小，退化为原有的"字母序第一个发现"选择。
    models_by_device = {}
    if remote_mode:
        for m in models:
            device = MultiModelTester._infer_device(m)
            if device not in models_by_device:
                models_by_device[device] = m
    else:
        candidates_by_device = {}
        for m in models:
            device = MultiModelTester._infer_device(m)
            candidates_by_device.setdefault(device, []).append(m)
        for device, candidates in candidates_by_device.items():
            models_by_device[device] = min(
                candidates, key=lambda m: _estimate_model_dir_size_bytes(args.models, m)
            )

    if remote_mode:
        svc_multi = RemoteServiceManager(args.host, args.port)
    else:
        stage3_model = _pick_stage3_model(models)
        config_path_multi = Path(args.models) / stage3_model / "config.json"
        svc_multi = ServiceManager(args.exe_dir, args.host, args.port)
        svc_multi._log_dir = args.out_dir
        try:
            print(f"  启动服务（加载所有模型，使用 {stage3_model} 作为入口）...")
            svc_multi.start(str(config_path_multi))
            print(f"  等待端口可连接（多模型加载可能需要较长时间）...")
            if not wait_port_open(args.host, args.port, timeout=300, process=svc_multi.process):
                print(f"  ⚠ 端口 300s 内未可连接，仍然尝试进入测试")
            else:
                print(f"  ✓ 端口已可连接")
        except (RuntimeError, FileNotFoundError) as e:
            print(f"  ✗ 服务启动失败: {e}")
            stage3_startup_failed = True
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name="_multi_model_", round_num=1,
                endpoint="SERVICE_STARTUP", detail=str(e)
            ))
            all_results.append(TestResult(
                name="服务启动 (阶段 3)", round_num=1, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=0,
                detail=f"启动失败: {str(e)[:300]}", crashed=True
            ))

    if not stage3_startup_failed:
        try:
            perf_multi = PerfMonitor()
            pid_multi = svc_multi.get_pid()
            if pid_multi:
                perf_multi.start(pid_multi)

            multi_tester = MultiModelTester(args.host, args.port, svc_multi, perf_multi, round_num=1)
            multi_results = multi_tester.run_all(
                models_by_device=models_by_device,
                models_root=args.models if not remote_mode else None,
                remote_mode=remote_mode,
            )
            all_results.extend(multi_results)
            all_crash_events.extend(multi_tester.crash_events)

            perf_samples_multi = perf_multi.stop()
            all_perf_samples.extend(perf_samples_multi)
        except Exception as e:
            # 同样补上对应的 TestResult(crashed=True)，与 _run_model_suite/
            # _run_multimodal_suite 保持一致的"异常必须同时产生 TestResult 和 CrashEvent"规范。
            print(f"  ✗ 阶段 3 测试异常: {e}")
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(),
                model_name="_multi_model_", round_num=1,
                endpoint="GLOBAL", detail=str(e)
            ))
            all_results.append(TestResult(
                name="GLOBAL", round_num=1, model_name="_multi_model_",
                passed=False, status_code=0, latency_ms=0,
                detail=f"套件级未捕获异常: {e}", crashed=True
            ))
        finally:
            if not remote_mode:
                print(f"  停止服务...")
                svc_multi.stop()

    return all_results, all_perf_samples, all_crash_events


def _run_mnn_suite(args, models, remote_mode, out_dir):
    """--suite mnn：仅对 MNN 后端模型执行标准生命周期测试（MNN 完全不支持多模态,
    detect_modality 对 MNN 模型目录名天然返回空集合,无需额外判断）。"""
    mnn_models = [m for m in models if infer_backend(m)[0] == "mnn"]
    if not mnn_models:
        return [TestResult(
            name="MNN_FILTER", round_num=1, model_name="_mnn_",
            passed=False, status_code=0, latency_ms=0,
            detail="未发现任何 MNN 模型，跳过 mnn suite", skipped=True
        )], [], []
    return _run_model_suite(args, mnn_models, remote_mode, out_dir)


def _interleave_multimodal_and_llm(models):
    """将模型列表按"多模态能力"（detect_modality 是否非空）拆分为两组，再按各自数量比例
    均匀交替合并，使多模态模型与纯文本大语言模型在执行顺序上交替出现，而不是像
    discover_models() 默认的字典序那样让同类模型连续排在一起。组内相对顺序保持不变；
    任一组为空（例如环境里只有多模态模型或只有纯文本模型）时原样返回,不做任何调整。

    用途：排查是否存在"连续测试同类模型才会触发"的问题——例如疑似与 NPU/HTP 资源在
    连续多个多模态请求之间未被正确释放/重置有关的低频崩溃（参见 phi4-v81 崩溃排查记录）。
    交替执行可以让多模态与纯文本模型的加载/卸载互相穿插，而不是等一大串同类模型跑完。"""
    multimodal = [m for m in models if detect_modality(m)]
    llm_only = [m for m in models if not detect_modality(m)]
    if not multimodal or not llm_only:
        return list(models)
    result = []
    ia = ib = 0
    la, lb = len(multimodal), len(llm_only)
    while ia < la or ib < lb:
        if ib >= lb:
            take_multimodal = True
        elif ia >= la:
            take_multimodal = False
        else:
            take_multimodal = (ia / la) <= (ib / lb)
        if take_multimodal:
            result.append(multimodal[ia])
            ia += 1
        else:
            result.append(llm_only[ib])
            ib += 1
    return result


def _run_qnn_suite(args, models, remote_mode, out_dir):
    """--suite qnn：仅对 QNN 后端模型执行标准生命周期测试；多模态模型自动执行多模态用例、
    非多模态模型自动跳过（复用 APITester.run_all 中既有的 detect_modality 判定，无需额外指定）。
    多模态模型与纯文本大语言模型按交替顺序执行（_interleave_multimodal_and_llm），而不是
    discover_models() 默认字典序下同类模型连续排列，便于排查连续同类测试才会触发的问题。"""
    qnn_models = [m for m in models if infer_backend(m)[0] == "qnn"]
    if not qnn_models:
        return [TestResult(
            name="QNN_FILTER", round_num=1, model_name="_qnn_",
            passed=False, status_code=0, latency_ms=0,
            detail="未发现任何 QNN 模型，跳过 qnn suite", skipped=True
        )], [], []
    qnn_models = _interleave_multimodal_and_llm(qnn_models)
    return _run_model_suite(args, qnn_models, remote_mode, out_dir)


# ============================================================================
# prompt_fidelity suite —— 提示词压缩「保真度 + 可观测」量化回归
# ============================================================================
# 设计要点（改动前必读，避免把断言建在不成立的取证通道上）：
#   1. 取证通道只认 `[Prompt] [...]:\n<最终提示词>\n------------` 这一段（三后端统一由
#      genie_interface.cpp/mnn.cpp/llama_cpp.cpp 无条件打印），它是真正喂给推理引擎的文本。
#      绝不能整份日志做子串搜索：-g -g（level 2）会把**原始请求 JSON** 打进日志，原文里当然
#      带着 canary，直接搜日志必然假阳性。因此本套件只传单个 -g（level 1）。
#   2. 默认日志级别是 kWarning（config.h:63），`[Normal] Final prompt - Tokens: N` 是 kInfo，
#      不显式抬高级别就抓不到 token 预算证据 —— 启动时固定追加 -d 3。
#   3. **必须以 -n -1 启动**：整条压缩链（PreFilterMessages + FitMessagesToContext + 工具定义
#      Tier 降级 + Phase -1 摘要）只在 `IsStatelessMode()`（numResponse == -1，见
#      model_instance_config.h:69）时执行，而默认值是 30（model_config.h:721）。不传 -n -1 时
#      本套件测到的是「压缩被设计性关闭」的分支，所有保真断言都没有意义。
#   4. 必须自己起服务（需要 stdout 落盘 + 自定义命令行），远程模式精确跳过而不是假装通过。
_PF_CANARY_HEAD = "CANARY-HEAD-8F31A2"
_PF_CANARY_MID = "CANARY-MID-5C7B90"
_PF_CANARY_TAIL = "CANARY-TAIL-EXIT-CODE-137"
_PF_CANARY_JSON_FIRST = "CANARY-JSON-FIRST-11AA"
_PF_CANARY_JSON_LAST = "CANARY-JSON-LAST-99ZZ"
_PF_CANARY_ZH_TAIL = "CANARY-ZH-TAIL-EXIT-137"
_PF_CANARY_IMG_TEXT = "CANARY-IMG-TEXT-4D2E1"
# 场景 C 专用：round A（纯文本+skill）自己的请求内容 canary，与 round B 的
# `_PF_CANARY_IMG_TEXT` 对称。Step6 本轮实测发现直接拿 "weather" 关键字判定跨轮
# 串扰是一个测试设计缺陷——weather 技能在 scenario_a_skill_weather() 里被
# `set_skill_run_mode(..., "both")` 设成了全局持久状态，一旦设置就在整个测试会话
# 剩余时间里对所有模型的所有请求可见，与"是否发生了跨模型串扰"完全无关；用一个
# 嵌入在 round A 用户消息文本里的、不受相关性过滤影响的唯一 canary 才是与 round B
# 对称的正确判据（同 round B 的 `_PF_CANARY_IMG_TEXT` 一样，是消息 content 本身的
# 一部分，不经过技能相关性过滤这条已知有零分清空 bug 的路径）。
_PF_CANARY_TXT_A = "CANARY-TXT-A-8B3F0"
_PF_DROP_PLACEHOLDER_HINT = "earlier message(s) omitted"

# 最小 1x1 像素透明 PNG（占位图，与真实一致的合法 PNG 二进制，无需任何素材文件），
# 仅用于验证多模态 content-parts 请求链路本身能正常处理，不要求模型真的看懂图片内容。
_PF_MIN_PNG_B64 = ("iVBORw0KGgoAAAANSUhEUgAAAAEAAAABCAQAAAC1HAwCAAAAC0lEQVR42mNk"
                   "+A8AAQUBAScY42YAAAAASUVORK5CYII=")

# 最终提示词块：非贪婪匹配到分隔线为止。
# 注意：GenieAPIService.exe 的 stdout 被 Windows CRT 以文本模式重定向到文件时，每个
# 源码里的 "\n" 都会被自动转换成 "\r\n"（这不是我们代码的行为，是 CRT 标准输出的文本
# 模式转换）；`\n` 两侧都必须放宽为 `\r?\n`，否则 `-{6,}\n` 在真实遇到 `-{6,}\r\n` 时会
# 匹配失败，导致误判为"取证通道失效"（此前一版曾误诊为模型分支问题，已核实并非如此）。
_PF_PROMPT_BLOCK_RE = re.compile(r"\[Prompt\] \[[^\r\n]*\r?\n(.*?)\r?\n-{6,}\r?\n", re.S)
# token 预算证据行（Normal/Harmony 两条路径同格式）。
_PF_FINAL_TOKENS_RE = re.compile(r"Final prompt - Tokens: (\d+)")

# PromptLedger 响应头（Step 4 引入）。基线阶段这些头不存在，对应用例如实判失败，
# 这正是「现状不可观测」这条差距的机械证据。
_PF_LEDGER_HEADERS = (
    "X-Genie-Prompt-Context-Size",
    "X-Genie-Prompt-Tokens-In",
    "X-Genie-Prompt-Tokens-Out",
    "X-Genie-Prompt-Messages-In",
    "X-Genie-Prompt-Messages-Kept",
    "X-Genie-Prompt-Messages-Dropped",
    "X-Genie-Prompt-Messages-Truncated",
    "X-Genie-Prompt-Tools-Total",
    "X-Genie-Prompt-Tools-Kept",
    "X-Genie-Prompt-Tools-Tier",
    "X-Genie-Prompt-Skills-Total",
    "X-Genie-Prompt-Skills-Kept",
    "X-Genie-Prompt-Emergency-Truncated",
    "X-Genie-Prompt-Summarized",
    # D3（Step2）新增：ComputeRelevanceTokenBudget(kSkills) 实际算出的 skills 分区预算。
    # legacy 档（budget_partition.enabled=false）与 optimized 档（竞争时分区生效）下
    # 该值必然不同，是「D3 开关真实生效」的机械证据，不需要读日志判断。
    "X-Genie-Prompt-Skills-Budget-Tokens",
    # D2（Step3）新增：技能目录三档渐进披露的各档计数。三项之和恒等于 Skills-Kept；
    # skill_disclosure.enabled=false 时逐字节退化为 L2==Kept、L1/L0 恒为 0，
    # 这是「三档开关真实生效」的机械证据（不需要读日志判断）。
    "X-Genie-Prompt-Skills-L2",
    "X-Genie-Prompt-Skills-L1",
    "X-Genie-Prompt-Skills-L0",
)


class _PromptLogProbe:
    """按字节偏移增量读取服务 stdout 日志，把「本次请求产生的日志」与历史日志隔离开。

    每次请求前 mark()，请求后 read_new() 只拿新增内容 —— 否则上一个用例埋的 canary
    会污染下一个用例的断言（同一个服务进程、同一份日志文件）。
    """

    def __init__(self, log_path):
        self.log_path = Path(log_path) if log_path else None
        self._offset = 0

    def mark(self):
        self._offset = self._size()

    def _size(self):
        try:
            return self.log_path.stat().st_size if (self.log_path and self.log_path.exists()) else 0
        except OSError:
            return 0

    def read_new(self):
        if not self.log_path or not self.log_path.exists():
            return ""
        try:
            with open(self.log_path, "rb") as f:
                f.seek(self._offset)
                data = f.read()
        except OSError as e:
            return f"<read error: {e}>"
        return data.decode("utf-8", errors="replace")

    def last_prompt_block(self):
        """本次请求产生的最后一个最终提示词块；抓不到返回空字符串（调用方据此判 skip）。"""
        blocks = _PF_PROMPT_BLOCK_RE.findall(self.read_new())
        return blocks[-1] if blocks else ""

    def final_prompt_tokens(self):
        """本次请求日志里最后一次 `Final prompt - Tokens: N`；抓不到返回 None。"""
        hits = _PF_FINAL_TOKENS_RE.findall(self.read_new())
        return int(hits[-1]) if hits else None


def _pf_filler_lines(tag, count):
    """生成体量填充行（每行约 100 字符），内容里刻意不含任何高信号词，
    确保「无高信号行」等价性用例的语义成立。"""
    return "\n".join(
        f"[{tag}] line {i:05d} routine progress record, nothing notable here, padding padding padding"
        for i in range(count)
    )


def _pf_build_long_tool_output():
    """约 80K 字符的超长工具输出：头/中/尾三处唯一 canary，尾部是真实构建失败常见形态
    （报错行 + 退出码），这正是当前「保头弃尾」截断必然丢掉的部分。"""
    head = f">>> build log start marker {_PF_CANARY_HEAD}\n"
    mid_marker = f"[checkpoint] halfway marker {_PF_CANARY_MID}\n"
    tail = (
        "npm ERR! Build step failed with a non-zero status.\n"
        "npm ERR! Traceback (most recent call last):\n"
        "npm ERR!   File \"/app/build.py\", line 412, in <module>\n"
        "npm ERR! RuntimeError: linker terminated abnormally\n"
        f"process exited with {_PF_CANARY_TAIL}\n"
    )
    body_a = _pf_filler_lines("pre", 400)
    body_b = _pf_filler_lines("post", 400)
    return head + body_a + "\n" + mid_marker + body_b + "\n" + tail


def _pf_build_json_array_tool_output():
    """JSON 数组型工具响应：首项与末项各埋唯一标记。当前实现只保留前缀元素，
    末项（往往是汇总/失败项）必然被丢 —— 这条用例就是该差距的直接回归。"""
    items = [{"index": 0, "name": _PF_CANARY_JSON_FIRST, "status": "ok",
              "note": "first entry of the result array"}]
    for i in range(1, 299):
        items.append({"index": i, "name": f"entry-{i:04d}", "status": "ok",
                      "note": "routine entry padding padding padding padding padding padding"})
    items.append({"index": 299, "name": _PF_CANARY_JSON_LAST, "status": "failed",
                  "note": "summary entry: 1 failed, exit code 137"})
    return json.dumps(items, ensure_ascii=False)


def _pf_build_chinese_long_text():
    """中文长文本：字符/token 比与英文差异显著，用于回归「阈值按字符算导致压缩力度不可控」。"""
    para = ("本段用于构造中文长文本样本，验证按字符计算的压缩阈值在中文语料下是否仍能把最终提示词"
            "控制在上下文预算之内。这里刻意使用连续的中文叙述文本，不含任何英文关键字。")
    return "\n".join(f"第{i:04d}段：{para}" for i in range(260)) + f"\n最终结论：{_PF_CANARY_ZH_TAIL}\n"


def _pf_build_tool_schemas(count=17):
    """count 个完整 JSON Schema 工具定义，逼出 PromptOptimizer 的 Tier 降级。
    工具名沿用 prompt_optimizer.cpp 已内置的通用名（read/write/...）之外再补足数量，
    实现层不做任何调用方判别，这里也只是「一份体量足够大的通用请求」。"""
    base_names = ["read", "write", "edit", "search", "list_dir", "run_command", "grep",
                  "fetch_url", "create_file", "delete_file", "move_file", "copy_file",
                  "git_status", "git_commit", "run_tests", "format_code", "analyze_deps"]
    tools = []
    for name in base_names[:count]:
        tools.append({
            "type": "function",
            "function": {
                "name": name,
                "description": (f"Perform the {name} operation. This description is intentionally verbose "
                                f"so that the full JSON schema of all tools cannot fit into a small "
                                f"context window without tier degradation."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "path": {"type": "string", "description": "Absolute or relative target path."},
                        "content": {"type": "string", "description": "Payload used by the operation."},
                        "recursive": {"type": "boolean", "description": "Whether to apply recursively."},
                        "limit": {"type": "integer", "description": "Maximum number of entries to process."},
                    },
                    "required": ["path"],
                },
            },
        })
    return tools


def _pf_tool_roundtrip_messages(tool_content, user_followup):
    """构造 assistant(tool_calls) → tool(超长响应) → user(追问) 的合法三段结构。"""
    return [
        {"role": "system", "content": "You are a build assistant. Answer briefly."},
        {"role": "user", "content": "Please read the build log and tell me what happened."},
        {"role": "assistant", "content": "", "tool_calls": [
            {"id": "call_pf_1", "type": "function",
             "function": {"name": "read", "arguments": "{\"path\": \"build.log\"}"}}
        ]},
        {"role": "tool", "tool_call_id": "call_pf_1", "name": "read", "content": tool_content},
        {"role": "user", "content": user_followup},
    ]


def _pf_long_history_messages(rounds=24):
    """20+ 轮长历史，触发 FitMessagesToContext 的「整条丢弃」路径。"""
    msgs = [{"role": "system", "content": "You are a helpful assistant. Answer briefly."}]
    for i in range(rounds):
        msgs.append({"role": "user", "content":
                     f"Round {i:02d} question: {_pf_filler_lines(f'q{i}', 12)}"})
        msgs.append({"role": "assistant", "content":
                     f"Round {i:02d} answer: {_pf_filler_lines(f'a{i}', 12)}"})
    msgs.append({"role": "user", "content": "Now summarize in one short sentence."})
    return msgs


def _pf_build_min_png_data_uri():
    """最小 1x1 像素 PNG 占位图（透明像素）的 OpenAI content-parts data URI，
    用于「纯图片单问」用例——不要求模型真的看懂图片内容，只验证请求链路本身
    能正常处理多模态 content 并保留伴随的文字说明。"""
    return f"data:image/png;base64,{_PF_MIN_PNG_B64}"


def _pf_result(name, model_name, passed, status_code, latency_ms, detail,
               response_data=None, skipped=False):
    return TestResult(
        name=name, round_num=1, model_name=model_name,
        passed=passed, status_code=status_code, latency_ms=latency_ms,
        detail=detail, skipped=skipped, ignorable=False,
        response_data=response_data or {},
    )


def _pf_post_chat(host, port, body, timeout=900):
    return requests.post(f"http://{host}:{port}/v1/chat/completions", json=body, timeout=timeout)


def _pf_check_ledger_headers(headers):
    """返回 (缺失字段列表, 非法值字段列表, 已解析的数值字典)。"""
    missing, invalid, values = [], [], {}
    for h in _PF_LEDGER_HEADERS:
        raw = headers.get(h)
        if raw is None:
            missing.append(h)
            continue
        try:
            values[h] = int(str(raw).strip())
        except ValueError:
            invalid.append(f"{h}={raw!r}")
    return missing, invalid, values


def _run_prompt_fidelity_suite(args, models, remote_mode, out_dir):
    """--suite prompt_fidelity：提示词压缩的「信息保真度 + 对调用方可观测」量化回归。

    全部断言可机械核验，不依赖人工读日志、也不判模型答得对不对：
      1. 超长工具输出的**尾部** canary 是否仍在最终提示词里（当前「保头弃尾」的最大漏洞）；
      2. JSON 数组型响应的**末项**是否仍在（当前只保留前缀元素）；
      3. 长历史整条丢弃后是否留下占位痕迹；
      4. 17 个完整工具 Schema + 中文长文本下最终 token 是否落在上下文预算内；
      5. 非流式响应头 / 流式 status 帧是否回报同一套压缩账本；
      6. 中文问英文命名工具（纯天气单问）/ 纯图片单问两类最小化核心场景是否仍保真。
    """
    all_results = []
    all_crash_events = []
    all_perf_samples = []
    suite_model = "_prompt_fidelity_"

    if remote_mode:
        all_results.append(_pf_result(
            "PROMPT_FIDELITY: suite precondition", suite_model, False, 0, 0,
            "远程模式无法自定义服务命令行（需 -n -1 -g -d 3）也拿不到 stdout 日志，跳过提示词保真套件",
            skipped=True))
        return all_results, all_perf_samples, all_crash_events

    name_filter = {n.strip() for n in args.model_name.split(",")} if args.model_name else None
    candidates = [m for m in models if not name_filter or m in name_filter]
    # 最终提示词全文三后端都会打印，但 QNN 是本项目的常开主路径，优先选它，保证基线可复现。
    target = next((m for m in candidates if infer_backend(m)[0] == "qnn"), None) or (
        candidates[0] if candidates else None)
    if not target:
        all_results.append(_pf_result(
            "PROMPT_FIDELITY: suite precondition", suite_model, False, 0, 0,
            f"未发现可用模型（--model_name={args.model_name}）", skipped=True))
        return all_results, all_perf_samples, all_crash_events

    config_path = Path(args.models) / target / "config.json"
    if not config_path.exists():
        all_results.append(_pf_result(
            "PROMPT_FIDELITY: suite precondition", suite_model, False, 0, 0,
            f"缺失 config.json: {config_path}", skipped=True))
        return all_results, all_perf_samples, all_crash_events

    print(f"\n{'='*60}")
    print(f"阶段: 提示词压缩保真度与可观测性回归（模型: {target}）")
    print(f"{'='*60}")

    wait_port_closed(args.host, args.port, timeout=15)
    svc = ServiceManager(args.exe_dir, args.host, args.port)
    svc._log_dir = args.out_dir
    try:
        # -n -1：**关键**。整条压缩链只在 IsStatelessMode()（numResponse == -1）时执行，
        # 默认值 30 下 PreFilterMessages/FitMessagesToContext/工具 Tier 降级全部不跑，
        # 提示词会原样送进引擎并由引擎侧 "Context Size was exceeded." 默默截断。
        # -g：prompt 压缩调试日志 level 1（**不能用 -g -g**，level 2 会把原始请求 JSON
        # 打进日志，canary 断言必然假阳性）；-d 3：抬到 Info，否则 Final prompt token 行被过滤。
        svc.start(str(config_path), extra_args=["-n", "-1", "-g", "-d", "3"])
        if not wait_port_open(args.host, args.port, timeout=180, process=svc.process):
            all_results.append(_pf_result(
                "PROMPT_FIDELITY: suite precondition", suite_model, False, 0, 0,
                "端口 180s 内未可连接", skipped=True))
            return all_results, all_perf_samples, all_crash_events

        probe = _PromptLogProbe(svc._stdout_log)
        context_size = 0
        try:
            r = requests.post(f"http://{args.host}:{args.port}/contextsize",
                              json={"model": target}, timeout=120)
            if r.status_code == 200:
                context_size = int(r.json().get("contextsize", 0))
        except Exception as e:
            print(f"  [prompt_fidelity] 获取 contextsize 失败: {e}")
        print(f"  [prompt_fidelity] contextsize={context_size}")

        _pf_case_tail_canary(args, target, probe, all_results, all_crash_events)
        _pf_case_json_tail_item(args, target, probe, all_results, all_crash_events)
        _pf_case_drop_placeholder(args, target, probe, all_results, all_crash_events)
        _pf_case_tools_budget(args, target, probe, context_size, all_results, all_crash_events)
        _pf_case_chinese_budget(args, target, probe, context_size, all_results, all_crash_events)
        _pf_case_no_high_signal(args, target, probe, all_results, all_crash_events)
        _pf_case_ledger_headers(args, target, probe, context_size, all_results, all_crash_events)
        _pf_case_image_single_question(args, target, probe, all_results, all_crash_events)
        _pf_case_cross_language_relevance(args, target, probe, all_results, all_crash_events)
        _pf_case_relevance_still_filters(args, target, probe, all_results, all_crash_events)
        _pf_case_stream_ledger(args, target, all_results, all_crash_events)
    except (RuntimeError, FileNotFoundError) as e:
        all_results.append(_pf_result(
            "PROMPT_FIDELITY: suite precondition", suite_model, False, 0, 0,
            f"服务启动失败: {str(e)[:300]}", skipped=True))
    finally:
        svc.stop()
        svc._force_kill()

    return all_results, all_perf_samples, all_crash_events


def _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate):
    """统一的「发一次请求 → 抓本次日志 → 交给 evaluate 判定」外壳，
    把 HTTP/日志异常与断言逻辑分开，避免每个用例各写一遍 try/except。"""
    start = time.time()
    _trace_request(model, name, 1, "prompt_fidelity")
    if probe is not None:
        probe.mark()
    try:
        resp = _pf_post_chat(args.host, args.port, body)
    except Exception as e:
        latency = (time.time() - start) * 1000
        all_results.append(_pf_result(name, model, False, 0, latency,
                                      f"请求异常（服务可能已崩溃）: {str(e)[:300]}"))
        all_crash_events.append(CrashEvent(
            timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
            endpoint=name, detail=f"prompt_fidelity 请求异常: {str(e)[:200]}",
            request_history=_trace_snapshot()))
        return
    latency = (time.time() - start) * 1000
    prompt_text = probe.last_prompt_block() if probe is not None else ""
    try:
        passed, detail, data = evaluate(resp, prompt_text, probe)
    except Exception as e:
        all_results.append(_pf_result(name, model, False, resp.status_code, latency,
                                      f"断言执行异常: {str(e)[:300]}"))
        return
    all_results.append(_pf_result(name, model, passed, resp.status_code, latency, detail, data))


def _pf_case_tail_canary(args, model, probe, all_results, all_crash_events):
    """场景1：约 80K 字符超长工具输出，尾部含退出码。断言尾部 canary 仍在最终提示词里。"""
    name = "PROMPT_FIDELITY: tail canary survives oversized tool output"
    tool_content = _pf_build_long_tool_output()
    body = {
        "model": model,
        "messages": _pf_tool_roundtrip_messages(
            tool_content, "What exit code did the build finish with? Answer in one short sentence."),
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能从服务日志抓取到最终提示词块（[Prompt] ... 分隔线），取证通道失效", {}
        head_in = _PF_CANARY_HEAD in prompt_text
        mid_in = _PF_CANARY_MID in prompt_text
        tail_in = _PF_CANARY_TAIL in prompt_text
        compressed = len(prompt_text) < len(tool_content)
        data = {"tool_output_chars": len(tool_content), "final_prompt_chars": len(prompt_text),
                "head_canary": head_in, "mid_canary": mid_in, "tail_canary": tail_in,
                "compressed": compressed}
        if not compressed:
            return False, (f"最终提示词未被压缩（{len(prompt_text)} chars ≥ 工具输出 "
                           f"{len(tool_content)} chars），该用例失去意义，请换更小上下文的模型"), data
        detail = (f"tool_output={len(tool_content)} chars → final_prompt={len(prompt_text)} chars; "
                  f"head={head_in}, mid={mid_in}, tail={tail_in}")
        return tail_in, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_json_tail_item(args, model, probe, all_results, all_crash_events):
    """场景2：JSON 数组型工具响应，断言首项与末项均保留、中部带省略标记。"""
    name = "PROMPT_FIDELITY: json array keeps last item"
    tool_content = _pf_build_json_array_tool_output()
    body = {
        "model": model,
        "messages": _pf_tool_roundtrip_messages(
            tool_content, "Did any entry fail? Answer in one short sentence."),
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        first_in = _PF_CANARY_JSON_FIRST in prompt_text
        last_in = _PF_CANARY_JSON_LAST in prompt_text
        omitted_mark = "items omitted" in prompt_text
        compressed = len(prompt_text) < len(tool_content)
        data = {"tool_output_chars": len(tool_content), "final_prompt_chars": len(prompt_text),
                "first_item": first_in, "last_item": last_in, "omitted_marker": omitted_mark,
                "compressed": compressed}
        if not compressed:
            return False, (f"最终提示词未被压缩（{len(prompt_text)} ≥ {len(tool_content)} chars），"
                           f"该用例失去意义"), data
        detail = (f"json_array={len(tool_content)} chars → final_prompt={len(prompt_text)} chars; "
                  f"first={first_in}, last={last_in}, omitted_marker={omitted_mark}")
        return (first_in and last_in), detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_drop_placeholder(args, model, probe, all_results, all_crash_events):
    """场景3：24 轮长历史触发整条丢弃，断言保留区首部出现丢弃占位 +（Step 4 后）响应头
    Messages-Dropped > 0。丢弃占位是让模型知道「这里曾有内容」的唯一线索。"""
    name = "PROMPT_FIDELITY: dropped messages leave a placeholder"
    body = {
        "model": model,
        "messages": _pf_long_history_messages(24),
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        placeholder_in = _PF_DROP_PLACEHOLDER_HINT in prompt_text
        missing, invalid, values = _pf_check_ledger_headers(resp.headers)
        dropped = values.get("X-Genie-Prompt-Messages-Dropped")
        data = {"final_prompt_chars": len(prompt_text), "drop_placeholder": placeholder_in,
                "ledger_headers_missing": missing, "messages_dropped": dropped}
        detail = (f"drop_placeholder={placeholder_in}; messages_dropped="
                  f"{dropped if dropped is not None else 'header 缺失'}; "
                  f"final_prompt={len(prompt_text)} chars")
        if dropped is not None and dropped == 0:
            # 没触发丢弃 → 占位缺席是正确行为，本轮无从验证，如实跳过而不是误判失败。
            return False, detail + "；本轮未触发整条丢弃，无法验证占位痕迹", data
        return placeholder_in, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_tools_budget(args, model, probe, context_size, all_results, all_crash_events):
    """场景4：17 个完整工具 Schema，断言最终 token 落在上下文预算内、且响应头账本齐全。"""
    name = "PROMPT_FIDELITY: 17 tool schemas stay within budget"
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "You are a coding agent. Use tools when needed."},
            {"role": "user", "content": "List the files under the project root."},
        ],
        "tools": _pf_build_tool_schemas(17),
        "stream": False,
        "max_tokens": 64,
    }

    def evaluate(resp, prompt_text, probe_obj):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        final_tokens = probe_obj.final_prompt_tokens() if probe_obj else None
        log_text = probe_obj.read_new() if probe_obj else ""
        exceeds_msg = "exceeds context size" in log_text
        missing, invalid, values = _pf_check_ledger_headers(resp.headers)
        data = {"final_prompt_tokens": final_tokens, "context_size": context_size,
                "system_prompt_exceeds_log": exceeds_msg,
                "ledger_headers_missing": missing, "ledger_headers_invalid": invalid,
                "tools_tier": values.get("X-Genie-Prompt-Tools-Tier")}
        if final_tokens is None:
            return False, "未能从日志抓取 `Final prompt - Tokens: N`（是否漏传 -d 3？）", data
        within = context_size <= 0 or final_tokens <= context_size
        detail = (f"final_prompt_tokens={final_tokens}, context_size={context_size}, "
                  f"within_budget={within}, exceeds_log={exceeds_msg}, "
                  f"tools_tier={data['tools_tier'] if data['tools_tier'] is not None else 'header 缺失'}")
        return (within and not exceeds_msg), detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_chinese_budget(args, model, probe, context_size, all_results, all_crash_events):
    """场景5：中文长文本（字符/token 比与英文差异大），断言 token 口径下最终 token 不越界。
    这是「阈值按字符算导致压缩力度不可控」这条差距的直接回归。"""
    name = "PROMPT_FIDELITY: chinese long text stays within token budget"
    zh = _pf_build_chinese_long_text()
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "你是一个中文助手，回答要简短。"},
            {"role": "user", "content": zh},
            {"role": "user", "content": "请用一句话说明最终结论。"},
        ],
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, probe_obj):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        final_tokens = probe_obj.final_prompt_tokens() if probe_obj else None
        tail_in = _PF_CANARY_ZH_TAIL in prompt_text if prompt_text else False
        data = {"zh_chars": len(zh), "final_prompt_tokens": final_tokens,
                "context_size": context_size, "zh_tail_canary": tail_in}
        if final_tokens is None:
            return False, "未能从日志抓取 `Final prompt - Tokens: N`", data
        within = context_size <= 0 or final_tokens <= context_size
        detail = (f"zh_input={len(zh)} chars, final_prompt_tokens={final_tokens}, "
                  f"context_size={context_size}, within_budget={within}, zh_tail={tail_in}")
        return within, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_no_high_signal(args, model, probe, all_results, all_crash_events):
    """边界：内容里没有任何高信号行（纯正常输出）时，行为必须与关闭高信号提取时一致 ——
    仍然是「头部保留 + 不越界 + 200」，不能因为找不到高信号行而崩溃或吐空提示词。"""
    name = "PROMPT_FIDELITY: no high-signal lines behaves like baseline"
    tool_content = _pf_filler_lines("plain", 800)
    body = {
        "model": model,
        "messages": _pf_tool_roundtrip_messages(
            tool_content, "Summarize the log in one short sentence."),
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        head_kept = "[plain] line 00000" in prompt_text
        data = {"final_prompt_chars": len(prompt_text), "head_kept": head_kept}
        return head_kept, f"head_kept={head_kept}, final_prompt={len(prompt_text)} chars", data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_ledger_headers(args, model, probe, context_size, all_results, all_crash_events):
    """场景：非流式响应必须带全套 X-Genie-Prompt-* 账本响应头，且全部为合法整数、
    Tokens-Out ≤ Context-Size。空 tools/skills 场景下字段应为 0 而不是缺失。"""
    name = "PROMPT_FIDELITY: non-stream reports ledger via response headers"
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "You are a helpful assistant. Answer briefly."},
            {"role": "user", "content": "Say hello in one short sentence."},
        ],
        "stream": False,
        "max_tokens": 32,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        missing, invalid, values = _pf_check_ledger_headers(resp.headers)
        tokens_out = values.get("X-Genie-Prompt-Tokens-Out")
        hdr_ctx = values.get("X-Genie-Prompt-Context-Size")
        data = {"missing": missing, "invalid": invalid, "values": values,
                "contextsize_endpoint": context_size}
        if missing or invalid:
            return False, (f"账本响应头缺失 {len(missing)}/{len(_PF_LEDGER_HEADERS)} 项: "
                           f"{', '.join(missing[:6])}{'...' if len(missing) > 6 else ''}"
                           + (f"; 非法值: {', '.join(invalid)}" if invalid else "")), data
        within = hdr_ctx is None or hdr_ctx <= 0 or tokens_out <= hdr_ctx
        detail = (f"全部 {len(_PF_LEDGER_HEADERS)} 项账本响应头齐全且为合法整数; "
                  f"tokens_out={tokens_out}, context_size={hdr_ctx}, within_budget={within}")
        return within, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_image_single_question(args, model, probe, all_results, all_crash_events):
    """场景：纯图片单问——一张最小占位图 + 一句极短中文提问（OpenAI 多段 content-parts）。
    断言伴随图片的文字说明未被压缩链路当作可随意丢弃的普通历史消息处理（用唯一 canary
    标记该说明文本，断言其仍在最终提示词块里），且请求返回 200；不要求模型真的看懂图片
    内容。仅在目标模型具备视觉能力时运行——文本模型收到 image_url content 会被
    genie_interface.cpp 的 IEmbedding::set_content 直接 throw ReportError{"not support
    vision mode"}，对本场景无意义，如实跳过而不是误判失败。"""
    name = "PROMPT_FIDELITY: pure image single question keeps accompanying text"
    if "image" not in detect_modality(model):
        all_results.append(_pf_result(
            name, model, False, 0, 0,
            f"目标模型 {model} 不支持视觉模态（detect_modality 未命中 image），跳过纯图片单问用例",
            skipped=True))
        return
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "你是一个助手，可以看图回答问题。"},
            {"role": "user", "content": [
                {"type": "text", "text": f"{_PF_CANARY_IMG_TEXT} 这张图片怎么样？"},
                {"type": "image_url", "image_url": {"url": _pf_build_min_png_data_uri()}},
            ]},
        ],
        "stream": False,
        "max_tokens": 48,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        text_kept = _PF_CANARY_IMG_TEXT in prompt_text
        data = {"final_prompt_chars": len(prompt_text), "accompanying_text_kept": text_kept}
        detail = f"accompanying_text_kept={text_kept}, final_prompt={len(prompt_text)} chars"
        return text_kept, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_relevance_tools():
    """一个英文 `weather` 工具 + 几个明确无关的工具。工具名与描述均为纯英文，
    用于验证中文提问能否仍看得到它（相关性过滤的跳语言盲区）。"""
    def _t(name, desc):
        return {"type": "function", "function": {
            "name": name, "description": desc,
            "parameters": {"type": "object",
                            "properties": {"query": {"type": "string", "description": "Query string."}},
                            "required": ["query"]}}}
    return [
        _t("weather", "Query the current weather and forecast for a given city."),
        _t("stock_quote", "Look up the latest trading price of a listed company."),
        _t("translate_text", "Translate a piece of text between two languages."),
        _t("currency_convert", "Convert an amount from one currency into another."),
    ]


def _pf_case_cross_language_relevance(args, model, probe, all_results, all_crash_events):
    """场景：中文提问「上海的天气怎么样」+ 纯英文 `weather` 工具。

    当前实现下中文被逐字切词（上/海/的/天/气/...），与英文工具名及英文描述一个都
    命中不了 → 全部候选得 0 分 → FilterToolsByRelevance 返回空集，工具定义从提示词整段
    消失，模型压根不知道自己能查天气（用户实测现象：显式点名 weather 就能工作，只问
    天气就不行）。断言最终提示词里仍出现 `weather`。
    """
    name = "PROMPT_FIDELITY: chinese query still sees english-named tool"
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "你是一个助手，需要时可以调用工具。"},
            {"role": "user", "content": "上海的天气怎么样？"},
        ],
        "tools": _pf_relevance_tools(),
        "stream": False,
        "max_tokens": 64,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        weather_in = "weather" in prompt_text.lower()
        any_tool_in = any(t["function"]["name"] in prompt_text
                          for t in _pf_relevance_tools())
        data = {"weather_visible": weather_in, "any_tool_visible": any_tool_in,
                "final_prompt_chars": len(prompt_text)}
        detail = (f"weather_visible={weather_in}, any_tool_visible={any_tool_in}, "
                  f"final_prompt={len(prompt_text)} chars")
        return weather_in, detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_relevance_still_filters(args, model, probe, all_results, all_crash_events):
    """反向用例：候选里存在真实命中项时，不相关项必须仍被筛掉。

    防止「全零分兜底」被实现成「永不过滤」——那样虽然上一条用例会变绿，但相关性
    过滤本身就彻底失效了。英文提问 weather 时 `weather` 必须在、且至少一个明确无关
    的工具不在。"""
    name = "PROMPT_FIDELITY: relevance filter still drops unrelated tools"
    body = {
        "model": model,
        "messages": [
            {"role": "system", "content": "You are an assistant. Use tools when needed."},
            {"role": "user", "content": "What is the weather in Shanghai right now?"},
        ],
        "tools": _pf_relevance_tools(),
        "stream": False,
        "max_tokens": 64,
    }

    def evaluate(resp, prompt_text, _probe):
        if resp.status_code != 200:
            return False, f"HTTP {resp.status_code}: {resp.text[:200]}", {}
        if not prompt_text:
            return False, "未能抓取到最终提示词块，取证通道失效", {}
        lower = prompt_text.lower()
        weather_in = "weather" in lower
        unrelated = [n for n in ("stock_quote", "currency_convert", "translate_text")
                     if n in lower]
        data = {"weather_visible": weather_in, "unrelated_still_visible": unrelated}
        detail = (f"weather_visible={weather_in}, unrelated_still_visible={unrelated} "
                  f"(期望至少筛掉一个不相关工具，证明兜底未退化为「永不过滤」)")
        return (weather_in and len(unrelated) < 3), detail, data

    _pf_run_request(args, model, probe, name, body, all_results, all_crash_events, evaluate)


def _pf_case_stream_ledger(args, model, all_results, all_crash_events):
    """场景6：流式路径的账本回报。流式响应头在 Build() 之前就已发出，物理上无法承载账本，
    因此约定用既有 status 帧（status=prompt_optimized）承载同一套字段。"""
    name = "PROMPT_FIDELITY: stream reports the same ledger via status frame"
    body = {
        "model": model,
        "messages": _pf_tool_roundtrip_messages(
            _pf_build_long_tool_output(), "What exit code did the build finish with?"),
        "stream": True,
        "max_tokens": 48,
    }
    start = time.time()
    _trace_request(model, name, 1, "prompt_fidelity stream")
    ledger_frame = None
    try:
        with requests.post(f"http://{args.host}:{args.port}/v1/chat/completions",
                           json=body, stream=True, timeout=900) as r:
            status_code = r.status_code
            for raw in r.iter_lines():
                if not raw:
                    continue
                line = raw.decode("utf-8", errors="replace") if isinstance(raw, bytes) else raw
                if not line.startswith("data:"):
                    continue
                payload = line[5:].strip()
                if payload == "[DONE]":
                    break
                try:
                    obj = json.loads(payload)
                except ValueError:
                    continue
                # status/status_message 及 PromptLedger 字段均在 choices[0] 内（与
                # ResponseTools::statusDataJson 的既有 "preparing"/"summarizing" 等状态帧
                # 同一层级约定），不在顶层 —— 顶层只有 id/object/created/model/choices。
                choices = obj.get("choices") if isinstance(obj, dict) else None
                choice0 = choices[0] if isinstance(choices, list) and choices else None
                if isinstance(choice0, dict) and choice0.get("status") == "prompt_optimized":
                    ledger_frame = choice0
                    break
    except Exception as e:
        latency = (time.time() - start) * 1000
        all_results.append(_pf_result(name, model, False, 0, latency,
                                      f"流式请求异常: {str(e)[:300]}"))
        all_crash_events.append(CrashEvent(
            timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
            endpoint=name, detail=f"prompt_fidelity 流式请求异常: {str(e)[:200]}",
            request_history=_trace_snapshot()))
        return
    latency = (time.time() - start) * 1000
    got = ledger_frame is not None
    detail = ("收到 status=prompt_optimized 帧: "
              f"{json.dumps(ledger_frame, ensure_ascii=False)[:300]}" if got
              else "流式响应中未收到 status=prompt_optimized 账本帧（调用方在流式路径上完全无感）")
    all_results.append(_pf_result(name, model, got, status_code, latency, detail,
                                  {"ledger_frame": ledger_frame or {}}))


# ============================================================================
# --suite skill_capacity：二分搜索求「每个模型最多能同时装载多少个 skill 且仍能答对」
# 的具体前沿值（能力矩阵基线，见 .junie/plans/skill-capacity-frontier.md Step 1）。
#
# 判据（FR1，唯一通过条件）：
#   picked（选对技能）：round1 响应里 tool_calls[].function.name == "read" 且
#       arguments.path 命中目标技能 <location>；
#   answered（答对）：round2（把模拟的 SKILL.md 正文回填为 tool 消息后追问）的最终
#       回答文本里出现该技能唯一规定的答案码。
#   两条都满足才 pass；只满足其一记为 partial（不计入前沿，仅进曲线）。
#
# 复用既有 prompt_fidelity 取证设施（不新造统计口径）：_PromptLogProbe/
# _PF_PROMPT_BLOCK_RE/_pf_check_ledger_headers、`svc.start(..., extra_args=
# ["-n","-1","-g","-d","3"])`；`-g` 只能给一次，见 _run_prompt_fidelity_suite 注释。
# ============================================================================

# 合成技能池的主题词表：每个主题生成一个独立技能名，保证 N 个技能之间语义可区分
# （不是靠"只有一个技能"蒙对），干扰项与目标技能共享部分关键词以构成真正的相关性
# 竞争。目标技能固定用 "flux-capacitor-calibration"（index 由 _sc_build_skill_pool
# 的 target_index 参数决定它在池中的位置，默认放在池首）。
# Step 4：只有目标技能 description 才带的尾部 canary（不含任何计分关键词，不
# 影响 ScoreRelevance() 的同分约束），用于机械区分 L1（description 被截断）
# 与 L2（description 完整保留）——此前所有技能的 description 尾部逐字节相同，
# 使得 _sc_target_disclosure_form() 恒判定为 L2。
_SC_TARGET_TAIL_CANARY = "[SC-TAIL-9K2Q]"
_SC_TARGET_TOPIC = "flux-capacitor-calibration"
_SC_DISTRACTOR_TOPICS = [
    "flux-capacitor-diagnostics", "capacitor-array-maintenance", "anomaly-classification",
    "warp-core-calibration", "reactor-flux-monitoring", "capacitor-bank-replacement",
    "temporal-anomaly-triage", "power-grid-calibration", "flux-sensor-cleaning",
    "capacitor-firmware-update", "anomaly-log-analysis", "reactor-startup-checklist",
    "capacitor-thermal-inspection", "flux-relay-configuration", "warp-field-diagnostics",
    "capacitor-voltage-tuning", "anomaly-alert-routing", "reactor-shutdown-procedure",
    "capacitor-cell-balancing", "flux-capacitor-decommission", "sensor-array-calibration",
    "anomaly-report-archival", "capacitor-leak-detection", "flux-emitter-alignment",
    "reactor-fuel-rotation", "capacitor-noise-filtering", "anomaly-pattern-tagging",
    "flux-capacitor-backup-restore", "warp-drive-cooldown", "capacitor-grid-sync",
    "reactor-pressure-check", "flux-capacitor-firmware-rollback", "anomaly-escalation-policy",
    "capacitor-humidity-control", "sensor-drift-correction", "reactor-core-realignment",
    "flux-capacitor-spare-parts", "capacitor-discharge-safety", "anomaly-severity-scoring",
    "warp-coil-degauss", "reactor-vibration-analysis", "capacitor-mount-torque-check",
    "flux-capacitor-cloning", "anomaly-timeline-reconstruction", "capacitor-dust-removal",
    "sensor-array-recalibration", "reactor-fuel-purity-check", "flux-capacitor-export",
    "capacitor-array-relabeling", "anomaly-false-positive-review", "warp-field-dampening",
    "reactor-emergency-vent", "capacitor-serial-audit", "flux-capacitor-import",
    "sensor-baseline-reset", "reactor-noise-suppression", "capacitor-array-rewiring",
    "anomaly-cluster-merge", "flux-capacitor-benchmark", "warp-core-realignment",
    "reactor-log-rotation", "capacitor-array-decommission", "sensor-fault-isolation",
    "flux-capacitor-stress-test", "anomaly-dashboard-refresh",
    # 第三轮修正：以下 4 条与目标技能 "flux-capacitor-calibration" 逐词同分
    # （三个子词 flux/capacitor/calibration 全部命中，ScoreRelevance() 的 name
    # 子词双向子串匹配 ×3 权重下得分与目标相同）。加入它们之前，实测目标恒得
    # 9 分而 64 条干扰项最高只有 6 分（分布 {0:18, 3:34, 6:13}），目标靠“唯一
    # 高分”恒定夺冠，与计划声明的“区分度只能来自名字、多条干扰项同样具备该
    # 特征”不符；现在至少 4 条真正持有相同分数，为 Step 3 D2/D4 让筛选生效后
    # 验证“目标技能不是靠唯一分数取胜”留下机械可核验的对照组。
    "calibration-flux-capacitor-audit", "flux-capacitor-calibration-mirror",
    "flux-capacitor-calibration-backup", "calibration-flux-capacitor-replica",
]

# Step 5 阶段 C：锚点池的两个固定名单（详见 _sc_build_skill_pool 的 docstring）。
#
# _SC_ANCHOR_TOPICS —— k=2 条**锚点**：与目标同分（18 分）且名字字典序**早于**
# 目标 "flux-capacitor-calibration"（"calibration…" < "flux…"），因此在目录里
# （分数降序 + 同分名字升序）恒排在目标之前，使「目标恒非首条、且首条是一个
# 与它逐字节同构的同分候选」这个被阶段 B 证明为决定性的竞争条件在**所有 N 上
# 恒定存在**。两条都取自下面那 4 条同分名里 "calibration" 开头的部分——另两条
# ("flux-capacitor-calibration-mirror/-backup") 名字排序**晚于**目标，做不了锚点。
_SC_ANCHOR_TOPICS = [
    "calibration-flux-capacitor-audit",
    "calibration-flux-capacitor-replica",
]

# _SC_FILLER_TOPICS —— 填充项名单：这 18 条的名字侧关键词命中数**恒为 0**
# （离线复算自 _SC_DISTRACTOR_TOPICS，见 step5_stage_c.anchor_pool_offline_validation），
# 只拿与全体技能相同的描述侧 9 分，因此恒排在目标与锚点之后，改变 N 只会增删
# 它们、不会挤动目录前三位。仍保留真实感十足的主题词（不是 filler-000 这种
# 明显合成名），以维持单条目录条目体量与真实场景接近。
_SC_FILLER_TOPICS = [
    "reactor-startup-checklist", "warp-field-diagnostics", "reactor-shutdown-procedure",
    "reactor-fuel-rotation", "warp-drive-cooldown", "reactor-pressure-check",
    "sensor-drift-correction", "reactor-core-realignment", "warp-coil-degauss",
    "reactor-vibration-analysis", "reactor-fuel-purity-check", "warp-field-dampening",
    "reactor-emergency-vent", "sensor-baseline-reset", "reactor-noise-suppression",
    "warp-core-realignment", "reactor-log-rotation", "sensor-fault-isolation",
]

_SC_QUESTION = ("How do I perform flux capacitor calibration for a class-3 temporal anomaly? "
                "Use the appropriate skill to answer.")

# Step 5 收口切片：两个用途明确、互不混淆的池。
#
# _sc_build_skill_pool()（下方，未改名以保持向后兼容）= **同分池（tie pool）**：
# 目标与 k=2 条锚点严格同分（18 分），专门度量"同分时目录顺序决定选择"这一病理
# （Step 5 阶段 B/C 全部实验的载体）。**不得用它测前沿数字**——阶段 C 已实测证明
# 旧版本（干扰名/目标位置随 N 跳变）测出的"前沿 77"是构造产物而非真实容量，
# 即便重构为锚点池消除了跨 N 跳变，三路完全同分这个设计本身仍可能让前沿主要由
# tie-break 运气决定（Copilot 第 2 轮 D 项明确提出的风险）。
#
# _sc_build_capacity_pool()（新增）= **容量池（capacity pool）**：目标分数**严格
# 最高**，没有任何干扰项与它同分——因此目录里目标恒排第 1（分数降序排序下没有
# 平局可打破），前沿数字反映的是"预算/篇幅能不能同时容纳 N 个技能且模型仍答对"，
# 不再可能被"读错同分候选"这条病理污染。用于前沿二分搜索与两档提升倍数计算。
_SC_CAP_NEAR_TOPICS = [
    # 与目标共享 2/3 个 name 子词（flux+capacitor，命中 "calibration" 的那个不占），
    # 分数低于目标但高于填充项——用于确认"严格最高"里的"严格"二字是真的有验证过
    # 而不是目标一家独大到没有对照。恒在池内、跨 N 组成不变。
    "flux-capacitor-diagnostics",
    "flux-capacitor-backup-restore",
]


def _sc_build_capacity_pool(n, target_index=None):
    """容量池：目标分数严格最高、组成跨 N 恒定，专供前沿二分搜索使用（区别于
    上面 _sc_build_skill_pool 的"同分池"，见上方模块级注释）。

    构造（与 _sc_build_skill_pool 同一套 doc/description 生成器，只换名单）：
      * 目标固定为 `_SC_TARGET_TOPIC`（"flux-capacitor-calibration"，18 分，
        name 侧 flux/capacitor/calibration 三词全命中）。
      * `_SC_CAP_NEAR_TOPICS`（k=2，恒在池内）：与目标共享 flux+capacitor 两个
        子词但不含 "calibration"，分数**严格低于**目标（离线复算见
        skill_capacity_baseline.json 的 step5_final.capacity_pool_offline_validation），
        用于证明"严格最高"不是没有近似分数的对照组、而是真的验证过目标仍然胜出。
      * 其余为填充项（复用 `_SC_FILLER_TOPICS`，name 侧关键词命中数恒为 0，
        分数恒最低），改变 N 只增删它们，不影响目标/near 的相对排序。
      * 目标固定池内 index 0（`target_index` 保留仅为兼容旧实验入口——阶段 B
        已证明池内 index 不影响目录序号）。"""
    n = max(1, n)
    names = [_SC_TARGET_TOPIC]
    for j, topic in enumerate(_SC_CAP_NEAR_TOPICS):
        if len(names) >= n:
            break
        names.append(f"{topic}-{j:03d}")
    fi = 0
    while len(names) < n:
        topic = _SC_FILLER_TOPICS[fi % len(_SC_FILLER_TOPICS)]
        names.append(f"{topic}-{fi:03d}")
        fi += 1
    target_pos = 0
    if target_index is not None:
        target_pos = max(0, min(int(target_index), len(names) - 1))
        names[0], names[target_pos] = names[target_pos], names[0]
    metas = []
    xml_parts = ["<available_skills>"]
    for i, name in enumerate(names):
        is_target = (i == target_pos)
        desc = _sc_build_skill_description(name, is_target)
        location = _sc_skill_location(name)
        xml_parts.append(
            f"<skill><name>{name}</name><description>{desc}</description>"
            f"<location>{location}</location></skill>")
        metas.append({
            "name": name, "description": desc, "location": location,
            "is_target": is_target, "doc": _sc_build_skill_doc(name, is_target),
        })
    xml_parts.append("</available_skills>")
    skills_xml = "".join(xml_parts)
    target_skill = next(m for m in metas if m["is_target"])
    return skills_xml, metas, target_skill


def _sc_build_uniform_tie_pool(n):
    """全同分技能池：整池构成**一个**同分组，专用于 `skill_disclosure.tie_aware_l2`
    的最坏情形防护断言（不用于前沿搜索，也没有目标技能与答案码）。

    构造：只取 `_SC_FILLER_TOPICS`（离线复算与远程实测均确认它们彼此得分完全相同
    ——name 侧对本问题的关键词命中数恒为 0，description 逐词同构），因此
    `AssignSkillDetailLevels()` 排序后 `candidates[l2_top_k-1].score` 这个边界分数
    等于全池分数，`tie_aware_l2=true` 时扩组会一直扩到覆盖整池。"""
    n = max(1, n)
    names, fi = [], 0
    while len(names) < n:
        names.append(f"{_SC_FILLER_TOPICS[fi % len(_SC_FILLER_TOPICS)]}-{fi:03d}")
        fi += 1
    metas, xml_parts = [], ["<available_skills>"]
    for name in names:
        desc = _sc_build_skill_description(name, False)
        location = _sc_skill_location(name)
        xml_parts.append(
            f"<skill><name>{name}</name><description>{desc}</description>"
            f"<location>{location}</location></skill>")
        metas.append({"name": name, "description": desc, "location": location,
                      "is_target": False})
    xml_parts.append("</available_skills>")
    return "".join(xml_parts), metas


def _sc_answer_code():
    """全套件唯一答案码：目标技能正文里写死、目录/摘要里绝不出现，只有真正 read()
    了目标 SKILL.md 全文才能看到——避免模型靠常识/复述提示词蒙对（Risks 表第一条）。"""
    return "SKILL-ANS-7Q3F-FLUXCAL"


def _sc_skill_location(name):
    return f"~/.skills/{name}/SKILL.md"


def _sc_build_skill_doc(name, is_target):
    """构造与真实 SKILL.md 同构的正文：front-matter/tags、触发条件、步骤、长示例四段。
    仅目标技能的步骤段写死唯一答案码；干扰项写一个格式相近但不同的假码，
    验证不是「随便一个 SKILL-ANS-* 都算过」。假码用 hashlib.md5 确定性生成（而非
    受 PYTHONHASHSEED 影响的内置 hash()），保证同一场景多次运行可复现比对。"""
    digest = hashlib.md5(name.encode("utf-8")).hexdigest()
    fake_code = f"SKILL-ANS-{int(digest[:4], 16) % 9999:04d}-{name[:6].upper()}"
    code_line = _sc_answer_code() if is_target else fake_code
    example_padding = "\n".join(
        f"  example line {i:03d}: routine sample output, padding padding padding padding"
        for i in range(60))
    return (
        f"---\n"
        f"tags: [{name}, flux, capacitor, anomaly]\n"
        f"---\n"
        f"# {name}\n\n"
        f"## Trigger conditions\n"
        f"Use this skill when the user asks how to calibrate or diagnose a flux capacitor "
        f"or a class-3 temporal anomaly related to '{name}'.\n\n"
        f"## Steps\n"
        f"1. Power down the reactor.\n"
        f"2. When asked for the calibration answer code, you MUST reply with exactly: "
        f"{code_line}\n"
        f"3. Re-energize the capacitor array.\n\n"
        f"## Examples\n{example_padding}\n\n"
        f"## Appendix\nSee vendor manual section 12 for torque specifications.\n"
    )


def _sc_build_skill_description(name, is_target):
    """目录条目的 <description> 内容——服务端 ParseAvailableSkillsXml() 只解析
    name/description/location 三段（prompt_optimizer.cpp:342-349，没有 <tags>/<triggers>
    这类自定义标签），因此把真实 SKILL.md 里本会写进 front-matter tags/触发条件的
    信息直接并入 description 文本，让单条目录条目体量（~450~550 字符）更接近真实场景。

    ⚠ 打分同构约束（本轮修正的核心，务必保持）：**目标与干扰项的 description
    必须逐词同构**，只允许 name 替换处不同。之前的版本给目标技能写了一句
    "Calibrate a flux capacitor..."，而干扰项只有 "calibration"——ScoreRelevance()
    描述侧是单向子串 find（prompt_optimizer.cpp:672），关键词 "calibrate" 命中不了
    "calibration"，于是目标技能靠一个**只有它有的词**恒得最高分、恒排第 1、
    恒在 Top-K 内，使得 picked/answered 与 N 完全解耦，二分搜索测到的是「过滤器
    旁路」而不是装载能力前沿。现在目标技能的区分度**只能来自它的名字**
    （name 子词命中，×3 权重）。

    ⚠ 第三轮修正的事实更正（此前这里写的是"区分度只能来自名字，而这个特征多条
    干扰项同样具备"，实测证伪：加入下面这句之前，_SC_DISTRACTOR_TOPICS 里没有
    任何一条真正与目标同分——目标恒得 9 分，64 条干扰项分布为 {0:18, 3:34, 6:13}，
    最高只有 6 分，目标依然靠"唯一高分"恒定夺冠，只是换了个更隐蔽的唯一词
    优势，没有解决问题）。真正的修正是往 _SC_DISTRACTOR_TOPICS 里加入了 4 条
    "calibration-flux-capacitor-audit" 等同构名（flux/capacitor/calibration
    三词全部命中，得分与目标相同），目标现在与至少 4 条干扰项同分，才是名字
    特征"干扰项同样具备"这句话第一次成立。"""
    topic = name.replace('-', ' ')
    base = f"Operational playbook related to {topic}."
    tags_line = f"Tags: {name}, flux, capacitor, anomaly, calibration, reactor, maintenance."
    trigger_line = (f"Trigger when the user mentions '{name}', flux capacitor calibration, "
                     f"class-3 temporal anomalies, reactor core diagnostics, or capacitor "
                     f"array maintenance procedures.")
    filler = (f"This playbook covers standard operating procedures, safety checklists, "
              f"pre-flight diagnostics, common failure modes, and escalation paths for "
              f"{topic} scenarios encountered in the field.")
    # Step 4 判据修正：为目标技能追加一个只有它才有的尾部 canary
    # （不含任何计分关键词、不影响 ScoreRelevance() 的同分约束），使
    # _sc_target_disclosure_form() 能靠"尾部是否可见"机械区分 L1/L2，而不是像
    # 之前那样所有技能结尾逐字节相同、L2 判定恒为真。干扰项不追加，保持逐词同构。
    if is_target:
        return f"{base} {tags_line} {trigger_line} {filler} {_SC_TARGET_TAIL_CANARY}"
    return f"{base} {tags_line} {trigger_line} {filler}"


def _sc_build_skill_pool(n, target_index=None):
    """生成 N 个同构技能（1 目标 + k 条锚点 + 填充项），返回
    (skills_xml, skill_meta_list, target_skill)。

    ⚠ Step 5 阶段 C 的**锚点池重构**（消除跨 N 不可比的构造产物）。旧实现：
    干扰名由 `_SC_DISTRACTOR_TOPICS[(i*7+3)%68]` 派生、目标位置由 `md5(n)` 派生，
    于是「名字字典序早于目标的同分（18 分）干扰项」在不在池里随 N 无规律开关
    （实测 n=44→池内 index 11、64→41、76→51、**77→68**、78→56，其中 index 68
    这一格恰好是唯一那条排序先于目标的同分名，n=77 时被目标本身占掉）。
    后果：`AssignSkillDetailLevels()` 按「分数降序 + 同分名字升序」排目录，
    目标的目录序号（以及它落在 L2 还是 L1）会随 N 跳变，于是「N=77 通过 /
    N=78 失败」这个所谓相变点里混进了一个**与技能数量无关**的变量，
    Step 4 记录的前沿 77 与 1.75x 因此作废。

    现在的构造（保证跨 N 可比）：
      * 固定 k=2 条**锚点**（`_SC_ANCHOR_TOPICS`）恒在池内。它们与目标同分
        （名字侧 flux/capacitor/calibration 三词全命中 ×3 = 9，描述侧与全体
        同构 = 9，合计 18），且名字以 "calibration" 开头 → 字典序**恒早于**
        目标 "flux-capacitor-calibration"，因此在目录里**恒排在目标之前**。
        k=2 的取值理由：2 条已足够构成「同分竞争 + 目标恒非首条」这两个被阶段 B
        证明为决定性的条件（目标目录序号恒为 3，`l2_top_k=2` 下恒被降到 L1），
        再多只会白占预算、把池体量与 token 曲线一起抬高，反而削弱跨 N 可比性。
      * 其余为**填充项**（`_SC_FILLER_TOPICS`），名字侧关键词命中数恒为 0
        （离线复算：全部 18 条 name_score=0），只拿与全体相同的描述侧 9 分，
        因此恒排在目标与锚点之后、且不会因 N 变化挤动前三位。
      * 目标默认停在池内 index 0，不再由 `md5(n)` 派生。

    ⚠ 池内 index 与目录序号**完全无关**（目录只按分数降序 + 同分名字升序排，
    见 prompt_optimizer.cpp `AssignSkillDetailLevels()`），因此 `target_index`
    参数只保留给既有实验入口做兼容；阶段 B 已实测「洗池内 index」根本移动不了
    目录序号（四个 target_index 下 `target_catalog_pos` 恒为 3）。"""
    n = max(1, n)
    names = [_SC_TARGET_TOPIC]
    for j, topic in enumerate(_SC_ANCHOR_TOPICS):
        if len(names) >= n:
            break
        names.append(f"{topic}-{j:03d}")
    fi = 0
    while len(names) < n:
        topic = _SC_FILLER_TOPICS[fi % len(_SC_FILLER_TOPICS)]
        names.append(f"{topic}-{fi:03d}")
        fi += 1
    target_pos = 0
    if target_index is not None:
        target_pos = max(0, min(int(target_index), len(names) - 1))
        names[0], names[target_pos] = names[target_pos], names[0]
    metas = []
    xml_parts = ["<available_skills>"]
    for i, name in enumerate(names):
        is_target = (i == target_pos)
        desc = _sc_build_skill_description(name, is_target)
        location = _sc_skill_location(name)
        xml_parts.append(
            f"<skill><name>{name}</name><description>{desc}</description>"
            f"<location>{location}</location></skill>")
        metas.append({
            "name": name, "description": desc, "location": location,
            "is_target": is_target, "doc": _sc_build_skill_doc(name, is_target),
        })
    xml_parts.append("</available_skills>")
    skills_xml = "".join(xml_parts)
    target_skill = next(m for m in metas if m["is_target"])
    return skills_xml, metas, target_skill


def _sc_extract_read_calls(msg):
    """从 assistant message 里提取全部 tool_calls 中 function.name=="read" 的
    arguments.path 列表（解析失败的条目跳过，不让 400/畸形 JSON 拖垮统计）。"""
    paths = []
    if not isinstance(msg, dict):
        return paths
    for tc in msg.get("tool_calls") or []:
        fn = tc.get("function") if isinstance(tc, dict) else None
        if not isinstance(fn, dict) or fn.get("name") != "read":
            continue
        try:
            args_obj = json.loads(fn.get("arguments") or "{}")
        except ValueError:
            continue
        path = args_obj.get("path")
        if isinstance(path, str):
            paths.append(path)
    return paths


def _sc_single_trial(args, model, probe, n, target_skill, skills_xml, all_metas, timeout):
    """跑一次完整两轮对话，返回本次试探的原始证据字典（未做 majority vote）。"""
    system_text = ("You are a helpful assistant. Skills are not tools — you must call "
                   "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)
    round1_body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": system_text},
            {"role": "user", "content": _SC_QUESTION},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    evidence = {"n": n, "picked": False, "answered": False, "emergency_truncated": False,
                "tokens_out": None, "context_size": None, "skills_total": None,
                "skills_kept": None, "tools_tier": None, "http_ok": False, "error": None,
                "skills_budget_tokens": None, "target_in_prompt": None, "target_form": None,
                "skills_l2": None, "skills_l1": None, "skills_l0": None}
    try:
        if probe is not None:
            probe.mark()
        r1 = _pf_post_chat(args.host, args.port, round1_body, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round1 请求异常: {str(e)[:300]}"
        return evidence
    if r1.status_code != 200:
        evidence["error"] = f"round1 HTTP {r1.status_code}: {r1.text[:200]}"
        return evidence
    evidence["http_ok"] = True
    missing, invalid, values = _pf_check_ledger_headers(r1.headers)
    evidence["skills_total"] = values.get("X-Genie-Prompt-Skills-Total")
    evidence["skills_kept"] = values.get("X-Genie-Prompt-Skills-Kept")
    evidence["tools_tier"] = values.get("X-Genie-Prompt-Tools-Tier")
    evidence["emergency_truncated"] = bool(values.get("X-Genie-Prompt-Emergency-Truncated"))
    evidence["tokens_out"] = values.get("X-Genie-Prompt-Tokens-Out")
    evidence["context_size"] = values.get("X-Genie-Prompt-Context-Size")
    evidence["skills_budget_tokens"] = values.get("X-Genie-Prompt-Skills-Budget-Tokens")
    # 三档披露账本（D2）：Step 6 报告详情页要按 N 展示 L2/L1/L0 分布，这里只是把
    # 已经解析出来的既有账本头顺带记进证据字典，不新增第二套统计口径。
    evidence["skills_l2"] = values.get("X-Genie-Prompt-Skills-L2")
    evidence["skills_l1"] = values.get("X-Genie-Prompt-Skills-L1")
    evidence["skills_l0"] = values.get("X-Genie-Prompt-Skills-L0")

    # 独立机械断言（本轮修正第 1(b) 条）：目标技能必须真的进了最终提示词，
    # 即它必须在 Skills-Kept 集合内。账本只给数量不给名单，因此直接查 [Prompt]
    # 日志块里有没有目标技能的 Path 行（BuildStructuredSkillCatalog 渲染的就是
    # "Path: <location>"）。拓不到日志块时置 None（未知），不当成失败也不当成通过。
    # Step 5 A1：原判据 `location in block or name in block` 有假阳性通道——Step 2
    # 引入的同分干扰名（如 flux-capacitor-calibration-mirror-009）把目标名整段包含
    # 为子串，一旦筛选开始丢弃技能，该断言会把「干扰项在场」误判为「目标在场」。
    # 改为复用形态判据 _sc_target_disclosure_form()：形态非 None/absent 才算在场。
    if probe is not None:
        block = probe.last_prompt_block()
        if block:
            form = _sc_target_disclosure_form(block, target_skill)
            evidence["target_form"] = form
            evidence["target_in_prompt"] = (form not in (None, "absent"))

    try:
        msg1 = r1.json()["choices"][0]["message"]
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round1 响应结构异常（无 choices[0].message）"
        return evidence
    read_paths = _sc_extract_read_calls(msg1)
    picked_by_read = any(target_skill["location"] in p or p in target_skill["location"]
                          for p in read_paths)
    content1 = msg1.get("content") or ""
    picked_by_canary = _sc_answer_code() in content1
    evidence["picked"] = bool(picked_by_read or picked_by_canary)
    # 只答对/未选技能且未直接命中答案码 → 判 fail，不再花第二轮请求成本。
    if picked_by_canary and not read_paths:
        evidence["answered"] = _sc_answer_code() in content1
        return evidence
    if not read_paths:
        evidence["answered"] = False
        return evidence

    # 模拟文件系统：把 round1 里第一条 read 调用对应技能的正文回填为 tool 结果
    # （命中目标技能则回填含答案码的正文，命中干扰技能则回填其假码正文——不代读者作弊）。
    first_path = read_paths[0]
    matched_meta = next((m for m in all_metas if m["location"] == first_path
                          or first_path in m["location"] or m["location"] in first_path), None)
    tool_call = next((tc for tc in (msg1.get("tool_calls") or [])
                       if isinstance(tc, dict) and tc.get("function", {}).get("name") == "read"), None)
    if matched_meta is None or tool_call is None:
        evidence["answered"] = False
        return evidence
    # 弱化新近效应偏置（本轮修正第 3 条）：在含答案码的 tool 消息与最终追问之间插入
    # 若干与本题无关的填充轮次，让 answered 不再退化为「最后一条 tool 消息是否整条
    # 存活」的复述测试，而是要求模型跨过若干轮次仍能定位并保留住高负载下的正确信息。
    filler_turns = [
        {"role": "user", "content": "Before that, what is 17 + 25?"},
        {"role": "assistant", "content": "17 + 25 = 42."},
        {"role": "user", "content": "And what's the capital of Iceland?"},
        {"role": "assistant", "content": "The capital of Iceland is Reykjavik."},
    ]
    round2_body = {
        "model": model, "stream": False,
        "messages": round1_body["messages"] + [
            {"role": "assistant", "content": msg1.get("content") or "",
             "tool_calls": msg1.get("tool_calls")},
            {"role": "tool", "tool_call_id": tool_call.get("id", "call_sc_1"),
             "name": "read", "content": matched_meta["doc"]},
        ] + filler_turns + [
            {"role": "user", "content": "Now reply with the exact calibration answer code."},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    try:
        if probe is not None:
            probe.mark()
        r2 = _pf_post_chat(args.host, args.port, round2_body, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round2 请求异常: {str(e)[:300]}"
        return evidence
    if r2.status_code != 200:
        evidence["error"] = f"round2 HTTP {r2.status_code}: {r2.text[:200]}"
        return evidence
    try:
        content2 = r2.json()["choices"][0]["message"].get("content") or ""
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round2 响应结构异常（无 choices[0].message）"
        return evidence
    evidence["answered"] = _sc_answer_code() in content2
    return evidence


# ============================================================================
# Step 4：三实验正交定位下一个真瓶颈（Copilot 提出、采纳为测量手段，见
# skill-capacity-frontier.md「方案定稿前的 Copilot 交叉审」Q2/Q4）。
#
#   oracle    —— 直接注入正确 SKILL.md 全文，跳过选择，只测"答题能力"；
#   selection —— 正常 D2+D4 自选流程（即 _sc_single_trial 的两轮判据）；
#   nobody    —— 选中技能后不回填正文，只凭目录（技能名 + 描述）作答。
#
# 判据（写入 skill_capacity_baseline.json 供 Step 5 使用）：
#   oracle 就失败                        → 答题能力瓶颈（P2/D6/分页拉取都救不了）
#   oracle 成 / selection 败              → 长目录选择瓶颈（分页拉取路线对症）
#   selection 选对但读正文后失败、oracle 成 → 回填后二次溢出/注意力退化（P2 对症）
# ============================================================================

def _sc_experiment_oracle(args, model, probe, n, target_skill, skills_xml, all_metas, timeout):
    """oracle 档：跳过整个选择环节，构造"已经选中并读完目标 SKILL.md 正文"的
    对话历史，直接问答案码。system prompt 仍携带完整技能目录（与 selection 档
    同一提示词体量），只是不给模型实际做选择的机会——用于隔离"答题能力"。"""
    system_text = ("You are a helpful assistant. Skills are not tools — you must call "
                   "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)
    fake_call_id = "call_sc_oracle_1"
    fake_tool_calls = [{
        "id": fake_call_id, "type": "function",
        "function": {"name": "read", "arguments": json.dumps({"path": target_skill["location"]})},
    }]
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": system_text},
            {"role": "user", "content": _SC_QUESTION},
            {"role": "assistant", "content": "", "tool_calls": fake_tool_calls},
            {"role": "tool", "tool_call_id": fake_call_id, "name": "read",
             "content": target_skill["doc"]},
            {"role": "user", "content": "Now reply with the exact calibration answer code."},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    evidence = {"n": n, "mode": "oracle", "answered": False, "http_ok": False, "error": None}
    try:
        if probe is not None:
            probe.mark()
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"oracle 请求异常: {str(e)[:300]}"
        return evidence
    if r.status_code != 200:
        evidence["error"] = f"oracle HTTP {r.status_code}: {r.text[:200]}"
        return evidence
    evidence["http_ok"] = True
    try:
        content = r.json()["choices"][0]["message"].get("content") or ""
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "oracle 响应结构异常（无 choices[0].message）"
        return evidence
    evidence["answered"] = _sc_answer_code() in content
    return evidence


def _sc_experiment_nobody(args, model, probe, n, target_skill, skills_xml, all_metas, timeout):
    """nobody 档：正常走 round1 选择，但 round2 不回填目标 SKILL.md 正文
    （tool 消息内容替换为一句不含答案码的确认语），直接追问答案码——用于隔离
    "选对技能"与"读到正文才能答对"是否真的有因果关系。picked=False 时该次
    试探记为不适用（选择本身失败，与 nobody 想测的问题无关），不计入判据。"""
    system_text = ("You are a helpful assistant. Skills are not tools — you must call "
                   "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)
    round1_body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": system_text},
            {"role": "user", "content": _SC_QUESTION},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    evidence = {"n": n, "mode": "nobody", "picked": False, "answered": False,
                "applicable": False, "http_ok": False, "error": None}
    try:
        if probe is not None:
            probe.mark()
        r1 = _pf_post_chat(args.host, args.port, round1_body, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round1 请求异常: {str(e)[:300]}"
        return evidence
    if r1.status_code != 200:
        evidence["error"] = f"round1 HTTP {r1.status_code}: {r1.text[:200]}"
        return evidence
    evidence["http_ok"] = True
    try:
        msg1 = r1.json()["choices"][0]["message"]
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round1 响应结构异常（无 choices[0].message）"
        return evidence
    read_paths = _sc_extract_read_calls(msg1)
    picked = any(target_skill["location"] in p or p in target_skill["location"] for p in read_paths)
    evidence["picked"] = bool(picked)
    if not picked:
        # 首轮没选中目标技能，与"选对了但不给正文"这个问题无关，不适用。
        return evidence
    evidence["applicable"] = True
    tool_call = next((tc for tc in (msg1.get("tool_calls") or [])
                       if isinstance(tc, dict) and tc.get("function", {}).get("name") == "read"), None)
    if tool_call is None:
        return evidence
    round2_body = {
        "model": model, "stream": False,
        "messages": round1_body["messages"] + [
            {"role": "assistant", "content": msg1.get("content") or "",
             "tool_calls": msg1.get("tool_calls")},
            {"role": "tool", "tool_call_id": tool_call.get("id", "call_sc_nobody_1"),
             "name": "read", "content": "OK, file located. (content intentionally withheld)"},
            {"role": "user", "content": "Now reply with the exact calibration answer code."},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    try:
        if probe is not None:
            probe.mark()
        r2 = _pf_post_chat(args.host, args.port, round2_body, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round2 请求异常: {str(e)[:300]}"
        return evidence
    if r2.status_code != 200:
        evidence["error"] = f"round2 HTTP {r2.status_code}: {r2.text[:200]}"
        return evidence
    try:
        content2 = r2.json()["choices"][0]["message"].get("content") or ""
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round2 响应结构异常（无 choices[0].message）"
        return evidence
    evidence["answered"] = _sc_answer_code() in content2
    return evidence


def _sc_run_bottleneck_experiments(args, model, probe, n, repeat, timeout, results):
    """在给定 N（调用方取「前沿+1」这个第一个失败点）上跑 oracle/selection/nobody
    三实验各 repeat 次多数票，返回结论字典（写入 baseline json），并把分类结论追加
    进 results。

    健康判据归类（`_sc_result()` 恒 `ignorable=False`，故必须精确）：能给出确定分类
    时记 `passed=True`；`none_observed`/`inconclusive` 这两种「测不出」的情况记
    `skipped=True`（不是失败）；只有 `judge_contaminated`（nobody 档不读正文也答对，
    说明判据本身被污染）才真的记失败——那确实是必须立刻修的缺陷。"""
    skills_xml, all_metas, target_skill = _sc_build_skill_pool(n)

    def majority(trials, key):
        applicable = [t for t in trials if t.get("applicable", True) and t.get("http_ok")]
        if not applicable:
            return None
        votes = sum(1 for t in applicable if t.get(key))
        return votes * 2 > len(applicable)

    oracle_trials = [_sc_experiment_oracle(args, model, probe, n, target_skill, skills_xml, all_metas, timeout)
                      for _ in range(max(1, repeat))]
    selection_trials = [_sc_single_trial(args, model, probe, n, target_skill, skills_xml, all_metas, timeout)
                         for _ in range(max(1, repeat))]
    nobody_trials = [_sc_experiment_nobody(args, model, probe, n, target_skill, skills_xml, all_metas, timeout)
                      for _ in range(max(1, repeat))]

    oracle_pass = majority(oracle_trials, "answered")
    selection_pass = majority(
        [{"answered": t["picked"] and t["answered"] and t["target_in_prompt"] is not False,
          "http_ok": t["http_ok"], "applicable": True} for t in selection_trials], "answered")
    # selection 档失败时必须再分一层：是"没选中目标技能"（长目录选择瓶颈）还是
    # "选中并读完正文后仍答错"（回填后二次溢出/注意力退化）。只看 selection_pass
    # 无法区分这两者，而它们分别对应 Step 5 的两条完全不同的动作。
    selection_picked = majority(
        [{"answered": t["picked"], "http_ok": t["http_ok"], "applicable": True}
         for t in selection_trials], "answered")
    nobody_pass = majority(nobody_trials, "answered")
    nobody_applicable_count = sum(1 for t in nobody_trials if t.get("applicable"))
    # nobody 档是**判据有效性对照**，不是瓶颈指示器：答案码只写在 SKILL.md 正文里，
    # 因此不回填正文时模型**应当答不出**（nobody_pass=False 才是健康）。若它反而
    # 答对了，说明答案码可以不读正文猜到 / 从目录泄漏，整套判据被污染，此时任何
    # 瓶颈结论都不可信。
    judge_contaminated = (nobody_pass is True)

    if judge_contaminated:
        bottleneck = "judge_contaminated"
        conclusion = ("nobody 档（不回填 SKILL.md 正文）竟然也答对了：答案码可在不读正文的情况下"
                      "获得，判据被污染，本次瓶颈结论一律不可信，需先修判据。")
    elif oracle_pass is False:
        bottleneck = "answering_ability"
        conclusion = "oracle 档（正文已直接注入、无需选择）就失败：答题能力本身是瓶颈，P2/D6/分页拉取均无法解决。"
    elif oracle_pass and selection_pass is False and selection_picked is False:
        bottleneck = "long_catalog_selection"
        conclusion = "oracle 成、selection 败且多数试探连目标技能都没选中：长目录选择是瓶颈，指向分页拉取路线。"
    elif oracle_pass and selection_pass is False and selection_picked:
        bottleneck = "post_readback_overflow"
        conclusion = ("oracle 成、selection 选对了目标技能但读完正文后仍答错："
                      "回填后二次溢出/注意力退化是瓶颈，指向 P2（SKILL.md 分节压缩）。")
    elif oracle_pass and selection_pass:
        bottleneck = "none_observed"
        conclusion = ("三档在本 N 上均按预期表现（oracle/selection 通过、nobody 如期答不出），"
                      "本探测点未触及瓶颈边界——需在真实前沿之上的失败点重测才能定位瓶颈。")
    else:
        bottleneck = "inconclusive"
        conclusion = "三实验结果组合未落入任何一条预设判据（如实标注，不强行归类）。"

    detail = (f"三实验 @N={n}（repeat={repeat}）：oracle_pass={oracle_pass}，"
              f"selection_pass={selection_pass}（其中 selection_picked={selection_picked}），"
              f"nobody_pass={nobody_pass}（对照档，False 才健康；适用样本数="
              f"{nobody_applicable_count}/{len(nobody_trials)}，round1 未选中目标技能的试探不计入）；"
              f"结论：{conclusion}")
    data = {"n": n, "oracle_pass": oracle_pass, "selection_pass": selection_pass,
            "selection_picked": selection_picked, "nobody_pass": nobody_pass,
            "nobody_applicable_count": nobody_applicable_count,
            "judge_contaminated": judge_contaminated,
            "bottleneck": bottleneck, "conclusion": conclusion}
    indeterminate = bottleneck in ("inconclusive", "none_observed")
    results.append(_sc_result(f"SKILL_CAPACITY: bottleneck_experiment n={n}", model,
                              not indeterminate and not judge_contaminated, detail,
                              skipped=indeterminate, data=data))
    return data


def _sc_majority_probe(args, model, probe, n, repeat, timeout, pool_builder=None):
    """对同一个 N 重复 repeat 次取多数票，返回聚合曲线条目 + pass/partial 判定。

    通过判据（本轮修正后）三条同时成立：选对技能（read 命中目标 SKILL.md）
    + 答对答案码 + **目标技能真的在 Skills-Kept 集合内**（target_in_prompt 不为
    False；拓不到日志时为 None，不当失败）。

    `pool_builder`：Step 5 收口切片新增，默认 `_sc_build_skill_pool`（同分池，
    历史行为不变）。真实前沿二分搜索必须传 `_sc_build_capacity_pool`（容量池，
    目标分数严格最高，不受 tie-break 病理污染），见模块级注释与 `_sc_binary_search`。"""
    builder = pool_builder or _sc_build_skill_pool
    skills_xml, all_metas, target_skill = builder(n)
    trials = []
    for _ in range(max(1, repeat)):
        trials.append(_sc_single_trial(args, model, probe, n, target_skill, skills_xml, all_metas, timeout))

    def is_pass(t):
        return t["picked"] and t["answered"] and t["target_in_prompt"] is not False

    pass_votes = sum(1 for t in trials if is_pass(t))
    partial_votes = sum(1 for t in trials if (t["picked"] or t["answered"]) and not is_pass(t))
    passed = pass_votes * 2 > len(trials)  # 多数票
    partial = (not passed) and partial_votes * 2 >= len(trials)
    last = trials[-1]
    # 预算饱和标注（本轮修正第 1(c) 条）：skills_kept < skills_total 说明保留条数
    # 已由预算（而非 N）决定，N 再大提示词体量也不再增长——此时测到的
    # “通过”与装载能力解耦，不得用来算提升倍数。
    saturated = (last["skills_kept"] is not None and last["skills_total"] is not None
                 and last["skills_kept"] < last["skills_total"])
    curve_entry = {
        "n": n, "answered": last["answered"], "picked": last["picked"],
        "target_in_prompt": last["target_in_prompt"],
        "target_form": last.get("target_form"),
        "skills_kept": last["skills_kept"], "skills_total": last["skills_total"],
        "skills_budget_tokens": last["skills_budget_tokens"],
        "skills_l2": last.get("skills_l2"), "skills_l1": last.get("skills_l1"),
        "skills_l0": last.get("skills_l0"),
        "skills_kept_at_budget_cap": saturated,
        "tokens_out": last["tokens_out"], "context_size": last["context_size"],
        "tools_tier": last["tools_tier"], "emergency_truncated": last["emergency_truncated"],
        "http_ok": last["http_ok"], "error": last["error"],
        "pass_votes": pass_votes, "partial_votes": partial_votes, "trials": len(trials),
        "passed": passed, "partial": partial,
    }
    return passed, curve_entry


def _sc_binary_search(args, model, probe, max_n, repeat, timeout, pool_builder=None):
    """求最大可通过的 N（FR2），并如实标注是否真实收敛（本轮修正第 1 条）。

    `pool_builder`：Step 5 收口切片新增，透传给 `_sc_majority_probe`。前沿数字
    只能用容量池（`_sc_build_capacity_pool`）测出才可信——同分池（默认值）测出
    的"前沿"已被证明可能是 tie-break 产物（见 step5_stage_c 与 step5_final 留档），
    调用方求真实前沿时必须显式传容量池。

    先从 N=1 起倍增探测（1,2,4,8,...）找到一个真实失败的上界；如果倍增到
    `max_n`（硬上限）仍全部通过，说明真实前沿 ≥ max_n，返回
    `converged=False`——调用方必须据此标注「未收敛，需调大 --skill_capacity_max
    重测」，不得把 `frontier==max_n` 当成真实前沿去算提升倍数。
    找到失败上界后，再在 [last_pass, first_fail) 区间二分收敛到精确前沿值，
    返回 `converged=True`。

    返回 (frontier, converged, curve)。"""
    curve = []

    def test(n):
        passed, entry = _sc_majority_probe(args, model, probe, n, repeat, timeout,
                                            pool_builder=pool_builder)
        curve.append(entry)
        return passed

    if not test(1):
        return 0, True, curve

    last_pass, first_fail = 1, None
    n = 2
    while n <= max_n:
        if test(n):
            last_pass = n
            n *= 2
        else:
            first_fail = n
            break

    if first_fail is None:
        # 倍增到硬上限仍全部通过：真实前沿 >= max_n，未收敛，如实标注，
        # 不得让调用方把 last_pass/max_n 误当成真实前沿值。
        return last_pass, False, curve

    if first_fail <= last_pass + 1:
        # 倍增探测本身已收敛到相邻整数，无需再二分。
        return last_pass, True, curve

    lo, hi, best = last_pass + 1, first_fail - 1, last_pass
    while lo <= hi:
        mid = (lo + hi) // 2
        if test(mid):
            best = mid
            lo = mid + 1
        else:
            hi = mid - 1
    return best, True, curve


# 场景 4/6 的跨档位测量值暂存：{(model, scenario): {arm: measurement}}。
# 同一次进程内 legacy/optimized 两档顺序跑完后，用它做「两档必须出现可观测差异」
# 这条断言——这正是计划要求的「把 cjk 比例改回旧值可复现越界或过度压缩」的证据。
_SC_SCENARIO_MEASUREMENTS = {}


def _sc_build_cn_skill_pool(n):
    """场景 6 用的中文技能池：description/正文均为中文，问题也是中文。

    ⚠ 为什么必须是中文（本轮修正第 6 条）：上一轮用纯英文池复核 CJK 换算比例，
    CJK 占比恒为 0，`cjk_bytes_per_token` 分支根本不会被执行，「两档曲线逐点一致」
    是构造上的必然、不构成任何证据。中文池才能真正走进 CJK 分支。"""
    metas = []
    xml_parts = ["<available_skills>"]
    for i in range(max(1, n)):
        is_target = (i == 0)
        name = "磁通电容器校准" if is_target else f"反应堆巡检流程-{i:03d}"
        desc = (f"运维手册：{name}。适用场景：当用户询问磁通电容器校准、三级时间异常"
                f"处理、反应堆核心诊断或电容阵列维护流程时触发。本手册覆盖标准作业程序、"
                f"安全检查清单、飞行前诊断、常见故障模式与升级路径，内容与"
                f"{name}相关的现场场景一一对应，篇幅较长以逼近真实文档体量。")
        location = f"~/.skills/cn-{i:03d}/SKILL.md"
        xml_parts.append(f"<skill><name>{name}</name><description>{desc}</description>"
                         f"<location>{location}</location></skill>")
        metas.append({"name": name, "description": desc, "location": location,
                      "is_target": is_target})
        _ = is_target
    xml_parts.append("</available_skills>")
    return "".join(xml_parts), metas, metas[0]


def _sc_case_tool_flood_skill_floor(args, model, probe, arm, results, timeout):
    """场景 4：约 80K 字符超长工具输出 + N 个技能，验证技能目录不被整段挤没。

    optimized 档断言 `Skills-Kept >= 1` 且目标技能仍在最终提示词里；legacy 档
    只如实记录测量值（不断言），两档数值一并落盘用于对照——legacy 下若真被挤没，
    体现在记录里，而不是伪造成一条非豁免失败。"""
    n = 24
    skills_xml, metas, target = _sc_build_skill_pool(n)
    long_tool_output = _pf_build_long_tool_output()  # 约 80K 字符
    system_text = ("You are a helpful assistant. Skills are not tools — you must call "
                   "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": system_text},
            {"role": "user", "content": "Run the build and then answer: " + _SC_QUESTION},
            {"role": "assistant", "content": "", "tool_calls": [{
                "id": "call_sc_flood", "type": "function",
                "function": {"name": "read", "arguments": json.dumps({"path": "/app/build.log"})}}]},
            {"role": "tool", "tool_call_id": "call_sc_flood", "name": "read",
             "content": long_tool_output},
            {"role": "user", "content": _SC_QUESTION},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    name = f"SKILL_CAPACITY: {arm} scenario4 tool_flood_skill_floor"
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}"))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    block = probe.last_prompt_block() if probe is not None else ""
    # Step 5 阶段 A1 修正：原 `location in block or name in block` 对名字子串有
    # 假阳性通道——Step 2 引入的同分干扰名（如 `flux-capacitor-calibration-mirror-009`）
    # 把目标名整段包含为子串，一旦筛选开始丢弃技能该断言会静默失真。改为复用形态
    # 判据 `_sc_target_disclosure_form()`：形态非 None/absent 才算目标真的在场。
    target_form = _sc_target_disclosure_form(block, target)
    target_in_prompt = (target_form not in (None, "absent")) if block else None
    kept = values.get("X-Genie-Prompt-Skills-Kept")
    total = values.get("X-Genie-Prompt-Skills-Total")
    measurement = {
        "skills_kept": kept, "skills_total": total,
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
        "tools_kept": values.get("X-Genie-Prompt-Tools-Kept"),
        "tools_total": values.get("X-Genie-Prompt-Tools-Total"),
        "tokens_out": values.get("X-Genie-Prompt-Tokens-Out"),
        "context_size": values.get("X-Genie-Prompt-Context-Size"),
        "emergency_truncated": values.get("X-Genie-Prompt-Emergency-Truncated"),
        "target_in_prompt": target_in_prompt, "target_form": target_form,
        "prompt_block_available": bool(block),
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario4"), {})[arm] = measurement
    if missing:
        results.append(_sc_result(name, model, False,
                                  f"账本响应头缺失 {missing}，无法机械核验技能保底", data=measurement))
        return
    if arm == "legacy":
        results.append(_sc_result(
            name, model, True,
            f"legacy 档如实记录（不断言）：skills_kept={kept}/{total}, "
            f"target_in_prompt={target_in_prompt}, tokens_out={measurement['tokens_out']}",
            data=measurement))
        return
    ok = (kept is not None and kept >= 1) and (target_in_prompt is not False)
    detail = (f"80K 工具输出 + N={n} 技能：skills_kept={kept}/{total}（要求 ≥1）, "
              f"target_in_prompt={target_in_prompt}（要求非 False）, "
              f"skills_budget_tokens={measurement['skills_budget_tokens']}, "
              f"tokens_out={measurement['tokens_out']}/{measurement['context_size']}")
    results.append(_sc_result(name, model, ok, detail, data=measurement))


def _sc_case_tools_kept_no_regress(args, model, probe, arm, results, timeout):
    """场景 4b（第三轮评审第 4 条要求，补齐上一轮未落地的针对性硬断言）：
    17 个完整 JSON Schema 工具 + 带 `<available_skills>` 的系统提示词（即 D3 的
    竞争条件 HasBudgetContention() 成立），断言 `X-Genie-Prompt-Tools-Kept`
    在 legacy/optimized 两档不退化（optimized_tools_kept >= legacy_tools_kept）。
    这条直接钉住"tools 只在真的超过 tools_ratio 上限时才被削减、不能因为
    skills 也在场就无故少给"这一 D3 语义。"""
    n = 8  # 技能数量不必很大，只需确保确实触发竞争（同时有 skills 与 tools 候选）
    skills_xml, metas, target = _sc_build_skill_pool(n)
    system_text = ("You are a helpful assistant. Skills are not tools — you must call "
                   "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": system_text},
            {"role": "user", "content": "List the files under the project root."},
        ],
        "tools": _pf_build_tool_schemas(17),
        "max_tokens": 64,
    }
    name = f"SKILL_CAPACITY: {arm} scenario4b tools_kept_no_regress"
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}"))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    tools_kept = values.get("X-Genie-Prompt-Tools-Kept")
    tools_total = values.get("X-Genie-Prompt-Tools-Total")
    measurement = {
        "tools_kept": tools_kept, "tools_total": tools_total,
        "skills_kept": values.get("X-Genie-Prompt-Skills-Kept"),
        "skills_total": values.get("X-Genie-Prompt-Skills-Total"),
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario4b"), {})[arm] = measurement
    if missing:
        results.append(_sc_result(name, model, False,
                                  f"账本响应头缺失 {missing}，无法机械核验 Tools-Kept", data=measurement))
        return
    if arm == "legacy":
        results.append(_sc_result(
            name, model, True,
            f"legacy 档如实记录（不断言，供 optimized 档对照）：tools_kept={tools_kept}/{tools_total}",
            data=measurement))
        return
    legacy_measurement = _SC_SCENARIO_MEASUREMENTS.get((model, "scenario4b"), {}).get("legacy")
    if legacy_measurement is None or legacy_measurement.get("tools_kept") is None or tools_kept is None:
        results.append(_sc_result(
            name, model, False,
            "缺 legacy 档测量值（需 --skill_capacity_arms both），无法核验不退化",
            skipped=True, data=measurement))
        return
    ok = tools_kept >= legacy_measurement["tools_kept"]
    detail = (f"17 工具 Schema + N={n} 技能（触发 D3 竞争）：optimized tools_kept={tools_kept} "
              f">= legacy tools_kept={legacy_measurement['tools_kept']} ? {ok}；"
              f"tools_total={tools_total}")
    results.append(_sc_result(name, model, ok, detail, data=measurement))


def _sc_case_chinese_budget(args, model, probe, arm, results, timeout):
    """场景 6：中文长技能池 + 中文超长工具输出，验证 `Tokens-Out <= Context-Size`
    且日志无 `exceeds context size`；同时把 tokens_out 记入跨档位对照表，供
    「把 cjk 比例改回 4.0 是否可复现越界/过度压缩」这条断言使用。"""
    n = 24
    skills_xml, metas, target = _sc_build_cn_skill_pool(n)
    cn_tool_output = ("构建日志：" + "。".join(
        f"第{i:04d}行 例行进度记录，无异常，填充填充填充填充填充填充填充" for i in range(600)))
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": "你是一个中文助手。技能不是工具，使用前必须先 read 其 SKILL.md。\n" + skills_xml},
            {"role": "user", "content": "请先看构建日志，然后回答：如何对磁通电容器做三级时间异常校准？"},
            {"role": "assistant", "content": "", "tool_calls": [{
                "id": "call_sc_cn", "type": "function",
                "function": {"name": "read", "arguments": json.dumps({"path": "/app/build.log"})}}]},
            {"role": "tool", "tool_call_id": "call_sc_cn", "name": "read", "content": cn_tool_output},
            {"role": "user", "content": "如何对磁通电容器做三级时间异常校准？请使用合适的技能回答。"},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
    }
    name = f"SKILL_CAPACITY: {arm} scenario6 chinese_budget"
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        # 422 local input overflow 也是可观测证据，如实记录（legacy 档下可能出现）
        measurement = {"http_status": r.status_code, "body": r.text[:200]}
        _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario6"), {})[arm] = measurement
        results.append(_sc_result(name, model, arm == "legacy",
                                  f"HTTP {r.status_code}: {r.text[:200]}"
                                  f"（legacy 档下的越界本身即对照证据，如实记录）",
                                  data=measurement))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    new_log = probe.read_new() if probe is not None else ""
    overflow_hit = "exceeds context size" in new_log.lower()
    block = probe.last_prompt_block() if probe is not None else ""
    tokens_out = values.get("X-Genie-Prompt-Tokens-Out")
    context_size = values.get("X-Genie-Prompt-Context-Size")
    measurement = {
        "http_status": 200, "tokens_out": tokens_out, "context_size": context_size,
        "skills_kept": values.get("X-Genie-Prompt-Skills-Kept"),
        "skills_total": values.get("X-Genie-Prompt-Skills-Total"),
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
        "messages_truncated": values.get("X-Genie-Prompt-Messages-Truncated"),
        "emergency_truncated": values.get("X-Genie-Prompt-Emergency-Truncated"),
        "overflow_log_hit": overflow_hit,
        "prompt_block_bytes": len(block.encode("utf-8")) if block else 0,
        "target_in_prompt": (target["location"] in block or target["name"] in block) if block else None,
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario6"), {})[arm] = measurement
    if missing:
        results.append(_sc_result(name, model, False,
                                  f"账本响应头缺失 {missing}，无法机械核验中文预算", data=measurement))
        return
    ok = (tokens_out is not None and context_size is not None
          and tokens_out <= context_size and not overflow_hit)
    detail = (f"中文技能池 N={n} + 中文长工具输出：tokens_out={tokens_out} <= "
              f"context_size={context_size} ? {tokens_out is not None and context_size is not None and tokens_out <= context_size}；"
              f"日志出现 'exceeds context size' = {overflow_hit}；"
              f"skills_kept={measurement['skills_kept']}/{measurement['skills_total']}；"
              f"提示词块字节数={measurement['prompt_block_bytes']}")
    results.append(_sc_result(name, model, ok, detail, data=measurement))


_SC_CN_QUERY = ("请问如何对磁通电容器做校准？三级时间异常时的电容校准步骤是什么？"
                "请使用合适的技能回答。")

# D4 别名扩展的服务端日志行（prompt_optimizer.cpp::BuildRelevanceKeywords）。
# 它是「中文词元真的被扩展成英文意图词」的唯一直接机械证据；
# intent_aliases_enabled=false 时该行根本不会输出。
_SC_ALIAS_EXPANSION_RE = re.compile(r"intent alias expansion: (\d+) -> (\d+) keyword")


def _sc_target_disclosure_form(block, target):
    """从 `[Prompt]` 日志块里机械判定目标技能的披露档位形态。

    Step 4 修正：此前用 `description[-24:]` 判 L2/L1，但合成池所有技能结尾
    逐字节相同（"...scenarios encountered in the field."），且 `l2_top_k=2`
    保证必有 L2 条目，导致该函数恒返回 "L2"（只能区分 L0 vs 非 L0，"目标技能
    在 L2" 这一结论此前从未被真正证实）。现在只有目标技能的 description 携带
    唯一尾部 canary（`_SC_TARGET_TAIL_CANARY`），因此 canary 是否出现在日志块
    里才是判据；干扰项 description 没有 canary，不受此修正影响。

    三种渲染形态互斥，可逐字节区分：
      L0 = 单行 `- <name> -> <loc>`；
      L2 = `Path: <loc>` 且 description **完整**（canary 尾部可见）；
      L1 = `Path: <loc>` 但 description 被截断（canary 尾部不可见）。
    拿不到日志块时返回 None（调用方不当失败）。"""
    if not block:
        return None
    if f"- {target['name']} -> {target['location']}" in block:
        return "L0"
    if f"Path: {target['location']}" in block:
        return "L2" if _SC_TARGET_TAIL_CANARY in block else "L1"
    return "absent"


def _sc_skill_pool_system_text(skills_xml):
    return ("You are a helpful assistant. Skills are not tools — you must call "
            "the read tool on a skill's SKILL.md location before using it.\n" + skills_xml)


def _sc_case_cn_query_en_pool(args, model, probe, arm, results, timeout):
    """场景 2（D4 跨语言相关性升级的机械断言）：中文提问 + **纯英文**技能池。

    ↳ 判据设计的一次更正（实测驱动，已留证）：本用例最初用的是
    `Skills-Kept < Skills-Total`，实测得到 32/32 而失败——这不是 D4 没生效，而是
    该指标在 D2 三档披露下根本不再成立：D2 的设计目标就是「预算耗尽时降档而不是
    整条删除」，降档后全部技能都放得进预算 → Kept 必然等于 Total。
    改为三条真正针对 D4 的机械判据：
      (a) 服务端日志出现 `[BuildRelevanceKeywords] intent alias expansion: X -> Y`
          且 Y > X（中文词元真的被扩展成了英文意图词）——这是 D4 生效的直接证据；
      (b) 目标技能在纯中文提问下未被降到 L0（排序真的把它留在高档）——`tie_aware_l2`
          实测为 true 时收紧为「必须在最高档 L2」，为 false 时 L2 名额会被同分锚点按
          名字升序占满、目标落 L1 属预期，故只断言「不被降到 L0」；
      (c) `Skills-L0 >= 1`（确实拉开了档位差，不是全员同档）。
    legacy 档（intent_aliases_enabled=false）断言该日志行**不应出现**，
    两档差异即 D4 开关真实生效的机械证据。"""
    n = 32
    skills_xml, metas, target = _sc_build_skill_pool(n)
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": _sc_skill_pool_system_text(skills_xml)},
            {"role": "user", "content": _SC_CN_QUERY},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
        "max_tokens": 96,
    }
    name = f"SKILL_CAPACITY: {arm} scenario2 cn_query_en_pool"
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}"))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    block = probe.last_prompt_block() if probe is not None else ""
    new_log = probe.read_new() if probe is not None else ""
    alias_hits = _SC_ALIAS_EXPANSION_RE.findall(new_log)
    alias_expanded = any(int(b) > int(a) for a, b in alias_hits)
    kept = values.get("X-Genie-Prompt-Skills-Kept")
    total = values.get("X-Genie-Prompt-Skills-Total")
    l2 = values.get("X-Genie-Prompt-Skills-L2")
    l0 = values.get("X-Genie-Prompt-Skills-L0")
    target_form = _sc_target_disclosure_form(block, target)
    measurement = {
        "skills_kept": kept, "skills_total": total,
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
        "skills_l2": l2,
        "skills_l1": values.get("X-Genie-Prompt-Skills-L1"),
        "skills_l0": l0,
        "tokens_out": values.get("X-Genie-Prompt-Tokens-Out"),
        "context_size": values.get("X-Genie-Prompt-Context-Size"),
        "target_in_prompt": (target["location"] in block) if block else None,
        "target_form": target_form,
        "alias_expansion_log": alias_hits[:4], "alias_expanded": alias_expanded,
        "prompt_block_available": bool(block),
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario2"), {})[arm] = measurement
    if missing:
        results.append(_sc_result(name, model, False,
                                  f"账本响应头缺失 {missing}，无法机械核验跨语言区分度", data=measurement))
        return
    if arm == "legacy":
        # legacy 档：D4 已关，别名扩展日志行必须不出现（回滚等价性的直接证据）。
        rollback_ok = (not alias_hits)
        results.append(_sc_result(
            name, model, rollback_ok,
            f"legacy 档（intent_aliases_enabled=false）回滚等价性：别名扩展日志行未出现 ? "
            f"{rollback_ok}（实测 hits={alias_hits[:4]}，要求为空）；"
            f"skills_kept={kept}/{total}, L2/L1/L0={l2}/{measurement['skills_l1']}/{l0}, "
            f"target_form={target_form}",
            data=measurement))
        return
    tiered = (l0 is not None and l0 >= 1)
    # 目标档位判据必须按 `skill_disclosure.tie_aware_l2` 的**实测取值**分档，理由与场景 3
    # 完全一致（Step 5 收口已在那里修过同一处语义冲突，本用例当时漏改）：该开关默认 false
    # 时不会把整组同分技能一起提到 L2，于是 `l2_top_k=2` 被两条同分锚点（名字升序在目标之前）
    # 吃满、目标必然落到 L1 —— 这不是产品缺陷，「真正同分时谁进 L2」本就没有原则性答案。
    # 关闭档位下改用一条仍然成立、且**非恒真**的断言：目标不得被降到 L0（目标与锚点同属
    # 最高分组，必须落在 L2/L1；若被降到 L0 或整条缺失，断言照样失败）。
    tie_aware = _sc_tie_aware_l2_enabled(probe)
    measurement["tie_aware_l2"] = tie_aware
    if tie_aware is True:
        target_ok = target_form in (None, "L2")
        target_req = "要求 L2（tie_aware_l2=true 时同分组整组进 L2）"
    else:
        target_ok = target_form in (None, "L1", "L2")
        target_req = ("要求不被降到 L0（tie_aware_l2 未开启，L2 名额被同分锚点按名字升序占满，"
                      "目标落 L1 属预期，非缺陷）")
    ok = alias_expanded and tiered and target_ok
    detail = (f"中文提问 + 纯英文技能池 N={n}：别名扩展生效（日志 X->Y 且 Y>X）? "
              f"{alias_expanded}（hits={alias_hits[:4]}）；目标技能档位={target_form}"
              f"（{target_req}；拿不到 [Prompt] 日志块时为 None，不当失败）；"
              f"L0>=1（档位真的拉开）? {tiered}；"
              f"L2/L1/L0={l2}/{measurement['skills_l1']}/{l0}，Kept={kept}/{total}"
              f"（注：D2 降档而不删除，Kept==Total 是预期行为，不作为区分度指标）")
    results.append(_sc_result(name, model, ok, detail, data=measurement))


def _sc_entry_disclosure_form(block, meta):
    """通用版 `_sc_target_disclosure_form()`：对任意技能条目（目标或干扰项）判定
    其在 `[Prompt]` 日志块里的披露档位形态。判据是完整 description 是否整段出现
    （逐字节子串匹配），对干扰项同样有效（干扰项没有 canary，但完整 description
    本身就是唯一的、可直接子串匹配的字符串）。"""
    if not block:
        return None
    if f"- {meta['name']} -> {meta['location']}" in block:
        return "L0"
    if f"Path: {meta['location']}" in block:
        return "L2" if (meta.get("description") or "") in block else "L1"
    return "absent"


_SC_DISCLOSURE_LEVEL_RANK = {"L0": 0, "L1": 1, "L2": 2}

# 与目标技能同分的干扰项识别方式。Step 5 阶段 C 锚点池重构后，同分干扰项就是那
# k=2 条**锚点**（名字以 `_SC_ANCHOR_TOPICS` 里的主题词开头），不再需要按旧的
# `(i*7+3) % len(_SC_DISTRACTOR_TOPICS)` 规则反推池内 index——那条规则已随锚点池
# 一起废弃，继续用它会挑出一批与目标**不同分**的填充项，让 D4 排序断言失真。


def _sc_same_score_distractor_metas(n, metas, target):
    """从技能池 metas 里挑出与目标同分（18 分）的干扰项，即锚点。

    锚点名形如 `calibration-flux-capacitor-audit-000`，按 `_SC_ANCHOR_TOPICS`
    前缀匹配即可，与它们在池内的 index 无关（目录序号本就与池内 index 无关）。"""
    same_score = []
    for meta in metas:
        if meta["is_target"]:
            continue
        if any(meta["name"].startswith(f"{topic}-") for topic in _SC_ANCHOR_TOPICS):
            same_score.append(meta)
    return same_score


def _sc_target_not_outranked_by_same_score(block, target, same_score_metas):
    """D4 排序区分度的直接机械断言（不再只靠"别名扩展日志出现"这一间接信号）：
    **同分干扰项里没有任何一条被披露到比目标更高的档位**，即
    `target_rank >= max(distractor_ranks)`。若同分干扰项一个都没进入本次池
    （n 太小），返回 (None, ...) 由调用方按不适用处理，不当失败。

    判据从「严格高于同分干扰项档位中位数」改成这条，原因是与 Step 5 阶段 C 新增的
    `skill_disclosure.tie_aware_l2`（默认 true）存在**语义冲突**：该开关刻意不切开一组
    同分技能、把整组一起提到 L2，于是「严格高于」在数学上永不可能成立（三者档位全为
    2），会制造一条与产品行为无关的常红失败。这是断言与开关的语义冲突，不是产品缺陷。

    改后的判据**没有被削弱到恒真**：它仍然精确地拒绝阶段 B 实测到的那种病理形态
    ——`l2_top_k=2` 且 `tie_aware_l2=false` 时，两条同分锚点吃掉 L2 名额而目标被压到
    L1（target_rank=1 < max=2）→ 断言失败。也就是说，`tie_aware_l2=false` 下它依然
    保有真实的排序区分力，只是不再要求目标必须**独占**最高档。"""
    if not same_score_metas:
        return None, None, None
    target_form = _sc_target_disclosure_form(block, target)
    target_rank = _SC_DISCLOSURE_LEVEL_RANK.get(target_form)
    distractor_ranks = sorted(
        _SC_DISCLOSURE_LEVEL_RANK.get(_sc_entry_disclosure_form(block, m), -1)
        for m in same_score_metas)
    if target_rank is None or any(r < 0 for r in distractor_ranks):
        return None, target_rank, distractor_ranks
    return (target_rank >= max(distractor_ranks)), target_rank, distractor_ranks


def _sc_tie_aware_l2_enabled(probe):
    """从服务 stdout 日志里机械读出本次运行的 `skill_disclosure.tie_aware_l2` 实际取值
    （`model_manager.cpp` 启动时回显 `[Config] skill_disclosure loaded: ... tie_aware_l2=0/1`）。

    为什么需要它：场景 3 的「目标未被任何同分干扰项压过档位」这条断言**只有在
    `tie_aware_l2=true` 时才可能成立**——该开关关闭（Step 5 收口后的出厂默认）时，
    `l2_top_k=2` 会被两条同分锚点吃掉、目标按「同分名字升序」排第 3 而落到 L1，
    于是 `target_rank(1) >= max(distractor_ranks)(2)` 必然为假。这不是产品缺陷，
    也不是断言写错，而是「真正同分时谁进 L2」本就没有原则性答案（见留档 (c) 条）。
    因此该子断言按实际开关取值决定是否适用，而不是靠猜或恒当通过。

    返回 True/False，日志里找不到该回显时返回 None（不当通过也不当失败）。"""
    if probe is None or probe.log_path is None or not probe.log_path.exists():
        return None
    try:
        text = probe.log_path.read_text(encoding="utf-8", errors="replace")
    except OSError:
        return None
    hits = re.findall(r"skill_disclosure loaded:.*?tie_aware_l2=(\d)", text)
    if not hits:
        return None
    return hits[-1] == "1"


def _sc_case_disclosure_tiers(args, model, probe, arm, results, timeout):
    """场景 3（D2 三档渐进披露的机械断言）：同一 N 下

      - 两档共同硬断言：`Skills-L2 + Skills-L1 + Skills-L0 == Skills-Kept`；
      - optimized 档：`L1 + L0 >= 1`（三档真的分了档，不是退化成全 L2），且目标技能
        以 L2 形态出现在最终提示词里（`Path:` 行 + description 尾部完整可见，
        而不是被截断的 L1 摘要或单行 L0）；
      - legacy 档（skill_disclosure.enabled=false）：`L2 == Kept` 且 `L1 == L0 == 0`，
        即逐字节退化到旧两档行为——这是回滚等价性的机械证据；
      - Step 4 新增、Step 5 收口修正：D4 排序区分度的直接断言——同分干扰项里没有
        任何一条被披露到**比目标更高**的档位（`target_rank >= max(distractor_ranks)`），
        不再只靠「别名扩展日志出现」这一间接信号。原「严格高于中位数」与
        `skill_disclosure.tie_aware_l2`（整组同分一起提到 L2）语义冲突，见
        `_sc_target_not_outranked_by_same_score()` 的说明。"""
    n = 24
    skills_xml, metas, target = _sc_build_skill_pool(n)
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": _sc_skill_pool_system_text(skills_xml)},
            {"role": "user", "content": _SC_QUESTION},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
        "max_tokens": 96,
    }
    name = f"SKILL_CAPACITY: {arm} scenario3 disclosure_tiers"
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}"))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    block = probe.last_prompt_block() if probe is not None else ""
    kept = values.get("X-Genie-Prompt-Skills-Kept")
    l2 = values.get("X-Genie-Prompt-Skills-L2")
    l1 = values.get("X-Genie-Prompt-Skills-L1")
    l0 = values.get("X-Genie-Prompt-Skills-L0")
    # 目标技能是否以 L2 全量形态出现（三种渲染形态互斥，可机械区分，见
    # _sc_target_disclosure_form）。
    target_form = _sc_target_disclosure_form(block, target)
    same_score_metas = _sc_same_score_distractor_metas(n, metas, target)
    outranks, target_rank, distractor_ranks = _sc_target_not_outranked_by_same_score(
        block, target, same_score_metas)
    measurement = {
        "skills_kept": kept, "skills_total": values.get("X-Genie-Prompt-Skills-Total"),
        "skills_l2": l2, "skills_l1": l1, "skills_l0": l0,
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
        "tokens_out": values.get("X-Genie-Prompt-Tokens-Out"),
        "context_size": values.get("X-Genie-Prompt-Context-Size"),
        "target_form": target_form, "prompt_block_available": bool(block),
        "same_score_distractor_count": len(same_score_metas),
        "not_outranked_by_same_score": outranks,
        "target_rank": target_rank, "distractor_ranks": distractor_ranks,
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario3"), {})[arm] = measurement
    if missing:
        results.append(_sc_result(name, model, False,
                                  f"账本响应头缺失 {missing}，无法机械核验三档披露", data=measurement))
        return
    if None in (kept, l2, l1, l0):
        results.append(_sc_result(name, model, False,
                                  f"三档账本字段解析失败：L2={l2}, L1={l1}, L0={l0}, Kept={kept}",
                                  data=measurement))
        return
    sum_ok = (l2 + l1 + l0 == kept)
    if arm == "legacy":
        rollback_ok = sum_ok and l1 == 0 and l0 == 0 and l2 == kept
        detail = (f"legacy 档（skill_disclosure.enabled=false）回滚等价性："
                  f"L2+L1+L0={l2}+{l1}+{l0}={l2 + l1 + l0} == Kept={kept} ? {sum_ok}；"
                  f"L2==Kept 且 L1==L0==0 ? {rollback_ok}（要求 True：逐字节退化到旧两档行为）；"
                  f"target_form={target_form}")
        results.append(_sc_result(name, model, rollback_ok, detail, data=measurement))
        return
    tiered = (l1 + l0) >= 1
    target_ok = target_form in (None, "L2")
    # D4 排序区分度断言的适用性（Step 5 收口小修）：该断言要求目标未被任何同分干扰项
    # 压过档位，而这一性质**只有 tie_aware_l2=true 时才可能成立**（关闭时两条同分锚点
    # 按名字升序吃掉 l2_top_k=2 的 L2 名额、目标必然落到 L1）。开关取值从服务启动
    # 日志的 `[Config] skill_disclosure loaded: ... tie_aware_l2=` 回显机械读出，
    # 关闭时该子断言不适用（如实记录实测档位，不当通过也不当失败），其余三条
    # （三档之和自洽 / 真的分档 / 目标不被降到 L0）仍然生效。
    tie_aware = _sc_tie_aware_l2_enabled(probe)
    measurement["tie_aware_l2"] = tie_aware
    rank_assertion_applicable = (outranks is not None) and (tie_aware is True)
    rank_ok = (outranks is True) if rank_assertion_applicable else True
    # 开关关闭时目标仍不得被降到 L0（这是关闭档位下仍然成立、且非恒真的性质：
    # 目标与同分锚点同属最高分组，必须落在 L2/L1，绝不能掉到只有名字的 L0）。
    target_not_l0 = target_form in (None, "L2", "L1")
    ok = sum_ok and tiered and target_ok and rank_ok and target_not_l0
    detail = (f"N={n}：L2+L1+L0={l2}+{l1}+{l0}={l2 + l1 + l0} == Kept={kept} ? {sum_ok}；"
              f"三档真的分档（L1+L0>=1）? {tiered}；目标技能形态={target_form}"
              f"（拿不到 [Prompt] 日志块时为 None，不当失败）；"
              f"skills_budget_tokens={measurement['skills_budget_tokens']}；"
              f"实测 tie_aware_l2={tie_aware}；"
              f"D4 排序区分度：同分干扰项 {len(same_score_metas)} 条，目标档位={target_rank}，"
              f"同分干扰项档位={distractor_ranks}，目标未被任何同分项压过档位？{outranks}"
              f"（该子断言仅在 tie_aware_l2=true 时适用：开关关闭时 l2_top_k=2 会被两条"
              f"同分锚点按名字升序吃掉、目标必然落到 L1，此性质物理上不可达；"
              f"本次适用？{rank_assertion_applicable}）；"
              f"目标未被降到 L0 ? {target_not_l0}")
    if not rank_assertion_applicable:
        results.append(_sc_result(
            name, model, sum_ok and tiered and target_not_l0,
            detail + "；注：tie_aware_l2 关闭（或同分干扰项为 0 条 / 拿不到日志块），"
                     "排序子断言按设计不适用，其余三条仍生效",
            data=measurement))
        return
    results.append(_sc_result(name, model, ok, detail, data=measurement))


def _sc_case_tie_group_kept_no_regress(args, model, probe, arm, results, timeout):
    """场景 3b（Step 5 收口新增的最坏情形防护断言）：**全同分技能池 + N 较大**时
    `Skills-Kept` 不得退化，即 `Skills-Kept == Skills-Total`。

    为什么需要这条：`skill_disclosure.tie_aware_l2` 会把 `l2_top_k` 边界向后扩展到
    覆盖完整同分组，而 `AssignSkillDetailLevels()` 的降档链只保证"不越界"，**不保证
    不丢弃**——第一个连 L0 都放不进预算的条目会触发
    `dropped = candidates.size() - idx; break;`，**整段丢弃剩余后缀**。整池同分
    （如 `zero_hit_keep_all` 兜底路径下全体候选同得 0 分）时扩组 = 整池 → 前若干条
    按 L2（每条约 137 token）吃掉几乎全部 skills 预算（约 6.5K token，约 47 条）→
    N=64 时必然丢弃后缀。既有用例测不到这一点：容量池边界同分组只有 2 条、同分池
    只有 3 条、场景 2 的 N=32 全 L2 仍在预算内。

    该开关默认值已在本轮改为 false（默认路径安全）；本断言的作用是：**任何人把它
    改回 true（或用配置打开）都会当场看到这条失败**，而不是让目录被静默截断。"""
    name = f"SKILL_CAPACITY: {arm} scenario3b tie_group_kept_no_regress"
    if arm != "optimized":
        results.append(_sc_result(
            name, model, False,
            "该断言针对 D2 三档披露路径（tie_aware_l2 的扩组风险），而 legacy 档"
            "skill_disclosure.enabled=false 时 AssignSkillDetailLevels() 完全不参与，"
            "按设计精确跳过", skipped=True))
        return
    n = 64
    skills_xml, metas = _sc_build_uniform_tie_pool(n)
    body = {
        "model": model, "stream": False,
        "messages": [
            {"role": "system", "content": _sc_skill_pool_system_text(skills_xml)},
            {"role": "user", "content": _SC_QUESTION},
        ],
        "tools": [_STATELESS_MODE_READ_TOOL_DEF],
        "max_tokens": 32,
    }
    if probe is not None:
        probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}"))
        return
    if r.status_code != 200:
        results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}"))
        return
    missing, invalid, values = _pf_check_ledger_headers(r.headers)
    kept = values.get("X-Genie-Prompt-Skills-Kept")
    total = values.get("X-Genie-Prompt-Skills-Total")
    measurement = {
        "n": n, "skills_kept": kept, "skills_total": total,
        "skills_l2": values.get("X-Genie-Prompt-Skills-L2"),
        "skills_l1": values.get("X-Genie-Prompt-Skills-L1"),
        "skills_l0": values.get("X-Genie-Prompt-Skills-L0"),
        "skills_budget_tokens": values.get("X-Genie-Prompt-Skills-Budget-Tokens"),
        "tokens_out": values.get("X-Genie-Prompt-Tokens-Out"),
        "context_size": values.get("X-Genie-Prompt-Context-Size"),
    }
    _SC_SCENARIO_MEASUREMENTS.setdefault((model, "scenario3b"), {})[arm] = measurement
    if missing or kept is None or total is None:
        results.append(_sc_result(
            name, model, False,
            f"账本响应头缺失 {missing}（Kept={kept}, Total={total}），无法机械核验",
            data=measurement))
        return
    ok = (kept == total)
    results.append(_sc_result(
        name, model, ok,
        f"全同分技能池 N={n}（整池构成一个同分组）：Skills-Kept={kept} == "
        f"Skills-Total={total} ? {ok}（要求 True：目录后缀不得被整段丢弃）；"
        f"L2/L1/L0={measurement['skills_l2']}/{measurement['skills_l1']}/"
        f"{measurement['skills_l0']}；skills_budget_tokens="
        f"{measurement['skills_budget_tokens']}；tokens_out={measurement['tokens_out']}/"
        f"{measurement['context_size']}",
        data=measurement))


def _sc_append_arm_contrast_results(model, results):
    """两档都跑过后追加跨档位对照断言：
      - 场景 4：skills_budget_tokens 在 legacy（budget_partition.enabled=false，
        等于单一总预算）与 optimized（竞争时分区生效）下必须不同 —— D3 开关真实
        生效的机械证据；
      - 场景 6：中文场景两档必须出现可观测差异（HTTP 状态、tokens_out、
        提示词块体量、是否越界任一不同），否则如实判失败，说明 P1 在该用例上
        无区分力、不能声称是真实修复。"""
    for scenario, key_desc in (("scenario2", "中文提问下的排序区分度（D4 开关生效证据）"),
                               ("scenario3", "三档披露计数差异（D2 开关生效证据）"),
                               ("scenario4", "skills_budget_tokens 差异（D3 开关生效证据）"),
                               ("scenario6", "中文场景两档可观测差异（P1 真实修复证据）")):
        arms_data = _SC_SCENARIO_MEASUREMENTS.get((model, scenario), {})
        name = f"SKILL_CAPACITY: {scenario} arm_contrast"
        if len(arms_data) < 2:
            results.append(_sc_result(
                name, model, False,
                f"只跑了 {list(arms_data)} 档，无法做两档对照（需 --skill_capacity_arms both）",
                skipped=True, data=arms_data))
            continue
        legacy, opt = arms_data.get("legacy", {}), arms_data.get("optimized", {})
        if scenario == "scenario2":
            # D4：两档对照的机械证据是「别名扩展日志行只在 optimized 档出现」
            # ——不能用 Kept 差异（D2 降档而不删除，Kept 在两档都等于 Total，
            # 实测 32/32 vs 32/32，已在场景 2 的 docstring 里留证）。
            ok = (not legacy.get("alias_expanded")) and bool(opt.get("alias_expanded"))
            detail = (f"{key_desc}：legacy alias_expanded={legacy.get('alias_expanded')}"
                      f"（hits={legacy.get('alias_expansion_log')}，要求 False） vs "
                      f"optimized alias_expanded={opt.get('alias_expanded')}"
                      f"（hits={opt.get('alias_expansion_log')}，要求 True）；"
                      f"legacy L2/L1/L0="
                      f"{legacy.get('skills_l2')}/{legacy.get('skills_l1')}/{legacy.get('skills_l0')} vs "
                      f"optimized={opt.get('skills_l2')}/{opt.get('skills_l1')}/{opt.get('skills_l0')}；"
                      f"legacy target_form={legacy.get('target_form')} vs "
                      f"optimized={opt.get('target_form')}；"
                      f"（Kept 两档均 == Total 是 D2 降档而不删除的预期行为，不作判据）")
        elif scenario == "scenario3":
            # D2：legacy 档必然 L1==L0==0（旧两档），optimized 档必然 L1+L0>=1（真分档）
            l_tier = (legacy.get("skills_l1") or 0) + (legacy.get("skills_l0") or 0)
            o_tier = (opt.get("skills_l1") or 0) + (opt.get("skills_l0") or 0)
            ok = (l_tier == 0 and o_tier >= 1)
            detail = (f"{key_desc}：legacy L2/L1/L0="
                      f"{legacy.get('skills_l2')}/{legacy.get('skills_l1')}/{legacy.get('skills_l0')}"
                      f"（要求 L1+L0==0） vs optimized="
                      f"{opt.get('skills_l2')}/{opt.get('skills_l1')}/{opt.get('skills_l0')}"
                      f"（要求 L1+L0>=1）；legacy target_form={legacy.get('target_form')} vs "
                      f"optimized={opt.get('target_form')}")
        elif scenario == "scenario4":
            l_budget, o_budget = legacy.get("skills_budget_tokens"), opt.get("skills_budget_tokens")
            ok = (l_budget is not None and o_budget is not None and l_budget != o_budget)
            detail = (f"{key_desc}：legacy skills_budget_tokens={l_budget} vs "
                      f"optimized={o_budget}（要求不同）；"
                      f"legacy skills_kept={legacy.get('skills_kept')} vs optimized={opt.get('skills_kept')}；"
                      f"legacy tools_kept={legacy.get('tools_kept')}/{legacy.get('tools_total')} vs "
                      f"optimized={opt.get('tools_kept')}/{opt.get('tools_total')}")
        else:
            diff_fields = [f for f in ("http_status", "tokens_out", "prompt_block_bytes",
                                       "overflow_log_hit", "messages_truncated")
                           if legacy.get(f) != opt.get(f)]
            if diff_fields:
                results.append(_sc_result(
                    name, model, True,
                    f"{key_desc}：差异字段={diff_fields}；legacy={legacy}；optimized={opt}",
                    data={"legacy": legacy, "optimized": opt}))
                continue
            # 处置 (c)（第三轮评审要求）：实测已证明 tokenizer 可用时该对照按设计必然
            # 全同——CountTokens() 优先用真实 tokenizer，fidelity.{cjk,ascii}_bytes_per_token
            # 只在拿不到 tokenizer 的回退分支参与运算，正常运行路径上无可观测差异。
            # 继续把它记为常红失败会淹没日后真正的新增失败（违反 failed==ignored 健康判据），
            # 改为 skipped=True 并保留两档实测字段作为该事实的机械凭证。
            results.append(_sc_result(
                name, model, True,
                f"{key_desc}：两档逐字段完全一致（差异字段集合为空），如实记为不可测而非常红失败——"
                f"fidelity.{{cjk,ascii}}_bytes_per_token 只在 tokenizer 不可用的回退分支参与运算，"
                f"正常路径无可观测差异，故该对照在当前环境下不可测；legacy={legacy}；optimized={opt}",
                skipped=True, data={"legacy": legacy, "optimized": opt}))
            continue
        results.append(_sc_result(name, model, ok, detail,
                                  data={"legacy": legacy, "optimized": opt}))


def _sc_arm_overrides(arm):
    """按档位（legacy/optimized）生成要写入 prompt_engineering.json 的
    prompt_optimization 子节覆盖字典。legacy = 全部 P1/D3/D2/D4 新开关关闭/退回旧值；
    optimized = 空字典（不覆盖，使用 model_config.h 里的新默认值）。
    P2/D6/D5 留给 Step4 落地后再扩展本函数。"""
    if arm == "legacy":
        return {
            "fidelity": {
                # 均改回 4.0 即逐字节回退到 P1 引入前的统一 length()/4 估算
                # （字段单位是 UTF-8 字节，不是字符；新默认值 cjk=3.0/ascii=4.0）
                "cjk_bytes_per_token": 4.0,
                "ascii_bytes_per_token": 4.0,
            },
            "budget_partition": {
                "enabled": False,
            },
            # D2：关掉三档渐进披露，退回旧两档行为
            # （FilterSkillsByRelevance + 全 L2 渲染，L1/L0 账本字段恒为 0）
            "skill_disclosure": {
                "enabled": False,
            },
            # D4：关掉跨语言意图别名表与 tags 参与打分，
            # 关键词集合与打分口径逐字节回退到 D4 引入前
            "relevance_filter": {
                "intent_aliases_enabled": False,
                "tag_weight": 0,
            },
        }
    # optimized：不写覆盖，直接依赖 C++ 侧默认值
    return {}


class _ScArmConfigOverride:
    """临时改写 <exe_dir>/prompt_engineering.json 的 prompt_optimization 子节以切换
    legacy/optimized 档位；改前备份、__exit__ 里 finally 还原，与 ModelDirSnapshot
    同一备份-还原模式。overrides={} 时（optimized 档且原文件已是新默认值）仍会
    读写一次文件（幂等，不产生副作用），便于统一代码路径。"""

    def __init__(self, exe_dir, arm):
        self.config_path = Path(exe_dir) / "config" / "prompt_engineering.json"
        self.arm = arm
        self.overrides = _sc_arm_overrides(arm)
        self._original_text = None
        self._existed = False

    def __enter__(self):
        if self.config_path.exists():
            self._existed = True
            self._original_text = self.config_path.read_text(encoding="utf-8")
            try:
                data = json.loads(self._original_text)
            except Exception:
                data = {}
        else:
            data = {}
        po = data.setdefault("prompt_optimization", {})
        for section, kv in self.overrides.items():
            po.setdefault(section, {}).update(kv)
        self.config_path.write_text(json.dumps(data, indent=2, ensure_ascii=False), encoding="utf-8")
        return self

    def __exit__(self, exc_type, exc_val, exc_tb):
        try:
            if self._existed:
                self.config_path.write_text(self._original_text, encoding="utf-8")
            elif self.config_path.exists():
                self.config_path.unlink()
        except Exception as e:
            print(f"WARNING: _ScArmConfigOverride 还原 {self.config_path} 失败: {e}")
        return False


def _sc_resolve_model(models, pattern):
    """在已发现模型目录名列表里按小写子串匹配定位目标模型，与
    _resolve_model_name()（Builder 集成类方法，7618 行）语义一致的独立函数版本，
    供直连模式（不依赖 Builder 的 usable 列表）复用。找不到返回 None。"""
    lower_pattern = pattern.lower()
    for m in models:
        if lower_pattern in m.lower():
            return m
    return None


def _sc_resolve_multimodal_model(models):
    """`qwen2.5_omini` 的四种命名变体兼容，与 _resolve_multimodal_model()（7905 行）
    同一惯例的独立函数版本（本套件不回退到 qwen2.5vl/qwen3_vl——按 FR4，模型缺失时
    如实精确跳过，不假装通过，不做模型替代）。"""
    for pattern in ("qwen2.5_omini", "qwen2.5-omini", "qwen2.5-omni", "qwen2.5_omni"):
        hit = _sc_resolve_model(models, pattern)
        if hit:
            return hit
    return None


def _sc_result(name, model, passed, detail, skipped=False, data=None):
    return TestResult(
        name=name, round_num=1, model_name=model, passed=passed, status_code=0,
        latency_ms=0, detail=detail, skipped=skipped, ignorable=False,
        response_data=data or {},
    )


# Builder 端到端确认用的技能数：与容量池 optimized 档已收敛前沿同源（Step 5 收口实测
# legacy 44 / optimized 118 / gain 2.6818x，`repeat=1`、`tie_aware_l2=false` 出厂默认）。
# 做成模块级常量而不是写死在函数体里，日后前沿被重测后只需改这一处。
_SC_BUILDER_TARGET_N = 118


def _sc_probe_builder_auth(builder):
    """机械探测 QAIModelBuilder 侧 `settings.auth.enabled` 的实际取值，返回
    (enabled_or_None, 人类可读判据)。

    判据来自 Builder 源码事实（`apps/api/main.py:206-210`）：SSO 相关路由
    （`/auth/login`、`/callback`、`/api/auth/me`）**只在 `settings.auth.enabled`
    为真时才注册**，且 enabled 为假时整条鉴权中间件被短路。因此
    `GET /api/auth/me` 返回 404 就是"鉴权关闭"的直接证据（路由不存在）。

    ↳ 一处按远程实测更正的判据（不要退回旧写法）：曾把「200 即已注册即已开启」
    直接当结论，实测该端点在**鉴权关闭**时同样返回 200，且响应体明写
    `{"auth_enabled": false, "authenticated": true, ...}` —— 即该路由并非严格
    只在 enabled 时注册。故现在优先采信响应体里的 `auth_enabled` 字段，
    只有拿不到该字段时才退回"路由存在 ⇒ 可能已开启"这条弱推断。
    探测异常返回 None（未知），不当成开启也不当成关闭——真正判断"是否被拦住"
    始终由调用方看业务 API 的实际状态码。"""
    try:
        r = builder.csrf.get("/api/auth/me", timeout=10)
    except Exception as e:
        return None, f"探测 GET /api/auth/me 异常: {type(e).__name__}: {str(e)[:160]}"
    if r.status_code == 404:
        return False, ("GET /api/auth/me → 404：SSO 路由未注册，即 settings.auth.enabled=False"
                       "（出厂默认），鉴权中间件已被短路，自动化请求不会被拦")
    body = None
    try:
        body = r.json()
    except ValueError:
        body = None
    if isinstance(body, dict) and isinstance(body.get("auth_enabled"), bool):
        enabled = body["auth_enabled"]
        return enabled, (f"GET /api/auth/me → {r.status_code}，响应体 auth_enabled={enabled}"
                         f"（直接采信该字段，优先于「路由是否注册」这条弱推断）；"
                         f"响应={r.text[:160]}")
    return True, (f"GET /api/auth/me → {r.status_code} 且响应体无 auth_enabled 字段："
                  f"退回弱推断「路由已注册 ⇒ 可能已开启」；响应={r.text[:160]}")


def _sc_case_builder_e2e(args, models, all_results, all_crash_events,
                         target_n=_SC_BUILDER_TARGET_N, timeout=180):
    """`--skill_capacity_mode builder/both` 的真实 Builder 驱动端到端确认。

    目的与直连通道**互补而非重复**：直连通道负责二分搜索求前沿（能读服务 stdout
    的 `[Prompt]` 块、能自定义启动参数），本用例只在直连已测出的前沿值 N 上确认
    「经真实 QAIModelBuilder 启动的 GenieAPIService 同样选对 + 答对」，是端到端背书。

    链路构成（每一步都只走 Builder 官方接口/文件系统标记，不改 Builder 任何源码）：
      1. `QAIModelBuilderManager.start()` 起 Builder（隔离数据目录 + 已注入
         `QAI_AUTH__ENABLED`，见该类 start() 实现）；
      2. `_sc_probe_builder_auth()` 先读一次鉴权实际取值并打印，真被拦住才处置；
      3. `list_skills()` → 临时 `npu.txt` 标记 → `set_skill_run_mode(id,"local")`
         → `reload_skills()`，让 Builder 侧本地技能目录提供者这条路径真实带电
         （范式与 `scenario_a_skill_weather()` 完全一致，`try/finally` 删除标记）；
      4. 复用 `QAIModelBuilderLocalModelTester` 的 `configure_genie_root()` /
         `inject_local_models()` / `discover_models_via_builder()` /
         `start_and_wait_ready()` 让 Builder 真正把 GenieAPIService 拉起来；
      5. 用容量池 `_sc_build_capacity_pool(N)`（与前沿同源，目标分数严格最高）
         向该服务端口发一次两轮对话，判据仍是「选对（read 命中目标 SKILL.md）
         且答对（回答含唯一答案码）」，与直连通道逐字节同一套 `_sc_single_trial`。

    **两条必须如实标注、不得伪造的架构限制**：
      * 容量池只能靠向 Builder 拉起的服务端口**直发 OpenAI 请求**注入——Builder
        自己的 conversation 聊天协议无法承载 118 个合成 `<available_skills>` 条目
        与自定义 `tools`。因此本用例验证的是"Builder 启动的服务进程"这条链路，
        不是"Builder 的聊天代理"这条链路。
      * 正因为走的是直发请求，`X-Genie-Prompt-*` 账本头在**这条注入通道上实际可
        观测**；而经 Builder SSE 聊天代理时它们结构性不可观测（Builder 帧协议不
        透传上游 HTTP 响应头，见 `scenario_a_skill_weather()` 的 ledger_note）。
        两种情形都按实际观测结果记录，既不伪造账本断言，也不谎称观测不到。

    环境不具备（远程模式 / Builder 起不来 / 技能列不出 / 目标模型或 config.json 缺失
    / 服务未就绪）一律 `skipped=True` 并写明环境原因，不伪造通过。`ModelDirSnapshot`
    安全网覆盖全程：0 违规静默通过（不产生正面记录），违规记 `crashed=True` /
    `ignorable=False`（崩溃永不豁免）。"""
    prefix = "SKILL_CAPACITY: builder_e2e"
    ph = "_skill_capacity_builder_"

    if getattr(args, "remote", False):
        all_results.append(_sc_result(
            f"{prefix} precondition", ph, False,
            "远程模式不适用（Builder 分支需要本机启动 Builder 子进程与 mklink /J 文件系统操作），"
            "精确跳过", skipped=True))
        return
    if not getattr(args, "genie_root_path", None):
        all_results.append(_sc_result(
            f"{prefix} precondition", ph, False,
            "缺少 --genie_root_path（或未通过 --exe_dir 复用），无法告知 Builder "
            "GenieAPIService 安装位置，精确跳过", skipped=True))
        return
    builder_dir = Path(getattr(args, "builder_dir", "") or "")
    if not builder_dir.is_dir():
        all_results.append(_sc_result(
            f"{prefix} precondition", ph, False,
            f"--builder_dir 不存在: {builder_dir}，精确跳过", skipped=True))
        return
    model = _sc_resolve_model(models, "qwen3-8b")
    if not model:
        all_results.append(_sc_result(
            f"{prefix} precondition", ph, False,
            f"未在已发现模型中匹配到 qwen3-8b（models={models}），精确跳过", skipped=True))
        return
    config_path = Path(args.models) / model / "config.json"
    if not config_path.exists():
        all_results.append(_sc_result(
            f"{prefix} precondition", model, False,
            f"缺失 config.json: {config_path}，精确跳过", skipped=True))
        return

    print(f"\n{'='*60}")
    print(f"阶段: skill_capacity Builder 真实驱动端到端确认（模型: {model}, N={target_n}）")
    print(f"{'='*60}")

    builder = QAIModelBuilderManager(
        args.builder_dir, args.host, args.builder_port, log_dir=args.out_dir,
        python_exe=getattr(args, "builder_python_exe", None),
        data_dir=getattr(args, "builder_data_dir", None),
    )
    tester = None
    npu_marker = None
    try:
        try:
            builder.start(timeout=120)
        except (RuntimeError, FileNotFoundError) as e:
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"Builder 启动失败（环境不具备）: {str(e)[:400]}", skipped=True))
            return

        auth_enabled, auth_detail = _sc_probe_builder_auth(builder)
        print(f"  [builder_e2e] settings.auth.enabled 探测: {auth_enabled}; {auth_detail}")

        list_ok, list_status, list_body = builder.list_skills()
        if not list_ok and list_status in (401, 403):
            all_results.append(_sc_result(
                f"{prefix} auth", model, False,
                f"Builder 鉴权实际拦截了自动化请求（GET /api/skills → {list_status}）：{auth_detail}；"
                "本切片不改 Builder 源码——请先在隔离数据目录下关闭鉴权"
                "（环境变量 QAI_AUTH__ENABLED=false，QAIModelBuilderManager.start() 已注入该变量，"
                "若仍被拦请检查该数据目录下的持久化配置是否显式打开了 auth）后重跑，精确跳过",
                skipped=True, data={"auth_enabled": auth_enabled, "auth_probe": auth_detail}))
            return
        if not list_ok:
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"GET /api/skills 失败（status={list_status}）: {str(list_body)[:240]}，精确跳过",
                skipped=True, data={"auth_enabled": auth_enabled, "auth_probe": auth_detail}))
            return

        skills = list_body.get("skills", []) if isinstance(list_body, dict) else []
        entry = next((s for s in skills if isinstance(s, dict)
                      and (s.get("skill_id") == "weather" or s.get("id") == "weather")), None)
        if entry is None:
            entry = next((s for s in skills if isinstance(s, dict)), None)
        if entry is None:
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"Builder 技能清单为空（GET /api/skills 返回 {str(list_body)[:200]}），"
                "无法验证 Builder 侧本地技能目录路径带电，精确跳过", skipped=True))
            return
        skill_id = entry.get("skill_id") or entry.get("id")

        # 临时 npu.txt 标记：`discovery.py` 要求技能满足 npu_optimized 才允许被设为
        # local/both（否则 resolve_skill_mode() 每次解析都会强制降级回 cloud），而
        # scan() 对该标记文件是逐次纯文件系统读取（无缓存）。范式与
        # scenario_a_skill_weather() 一致，finally 里无条件删除。
        if not entry.get("npu_optimized") and entry.get("skill_path"):
            try:
                candidate = Path(entry["skill_path"]).parent / "npu.txt"
                if not candidate.exists():
                    candidate.write_text(
                        "temporary marker created by test_service.py "
                        "_sc_case_builder_e2e() — safe to delete\n", encoding="utf-8")
                    npu_marker = candidate
            except OSError as exc:
                print(f"  [builder_e2e] 临时 npu.txt 标记创建失败（不阻塞本用例）: {exc!r}")

        mode_ok, mode_status, _mode_body = builder.set_skill_run_mode(skill_id, "local")
        reload_ok, reload_status, _reload_body = builder.reload_skills()
        print(f"  [builder_e2e] set_skill_run_mode({skill_id},'local') ok={mode_ok} "
              f"status={mode_status}; reload_skills ok={reload_ok} status={reload_status}")

        tester = QAIModelBuilderLocalModelTester(
            builder=builder, models_root=args.models,
            genie_root_path=args.genie_root_path, model_names=[model],
            genie_service_port=args.port, round_num=1,
            data_dir=getattr(args, "data_dir", None),
        )
        root_ok = tester.configure_genie_root()
        inject_ok = tester.inject_local_models() if root_ok else False
        found = tester.discover_models_via_builder() if inject_ok else []
        found_names = {m.get("name") for m in found if isinstance(m, dict)}
        if model not in found_names:
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"Builder 未发现注入的模型（root_ok={root_ok}, inject_ok={inject_ok}, "
                f"已发现={sorted(n for n in found_names if n)}），精确跳过", skipped=True))
            return

        started, status = tester.start_and_wait_ready(model, args.port)
        if not started:
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"Builder 未能把 GenieAPIService 拉到就绪状态（last_status={status}），精确跳过",
                skipped=True))
            return
        # Builder 固定以 `-n -1 -l` 启动 GenieAPIService（见
        # QAIModelBuilderLocalModelTester._build_chat_request_body 的说明），因此
        # IsStatelessMode() 成立、整条压缩链在这条链路上真实生效，N=118 在此有意义。
        command = status.get("command") if isinstance(status, dict) else None
        # Builder 的 /api/service/start 是 fire-and-forget，status.running=true 早于
        # GenieAPIService 真正 bind 端口（远程实测过一次 running=true 但随后直发请求被
        # WinError 10061 拒绝）。这里补一次真实 TCP 端口等待，把「还没起来」与「起来了
        # 但答不对」两种情形分开：等不到就精确跳过在 precondition 阶段，而不是把连接层
        # 异常混进能力判据。
        if not wait_port_open(args.host, args.port, timeout=180):
            all_results.append(_sc_result(
                f"{prefix} precondition", model, False,
                f"Builder 报告服务就绪（status={status}）但 {args.host}:{args.port} 在 180s 内"
                "始终不可连接，精确跳过（环境/链路问题，非能力结论）", skipped=True))
            return
        # 等过 LocalChatSkillCatalogProvider 的 3 秒 TTL 窗口，排除 set_mode 刚写入即
        # 读到旧缓存这条已知假阴性路径（同 scenario_a_skill_weather()）。
        time.sleep(4)

        skills_xml, metas, target = _sc_build_capacity_pool(target_n)
        bprobe = _BuilderLogProbe(builder.csrf)
        bprobe.mark()
        bprobe.start_live_tail()
        ev = _sc_single_trial(args, model, None, target_n, target, skills_xml, metas, timeout)
        raw_log = bprobe.stop_live_tail()
        target_in_builder_log = bool(raw_log) and (target["location"] in raw_log)

        ledger_seen = sorted(k for k in ("skills_total", "skills_kept", "skills_l2", "skills_l1",
                                        "skills_l0", "skills_budget_tokens", "tokens_out",
                                        "context_size") if ev.get(k) is not None)
        # 三条限制的措辞按 Copilot 反对派审查（Step 6）逐条回代码核实后收紧——原措辞
        # 「背书 Builder 启动的服务进程链路」被判**仍过强**，因为第 4 步之后 Builder 在
        # 请求面已完全退出因果链。不采纳它的 Q4（改走 Builder 官方 chat/SSE）：118 个合成
        # <available_skills> 条目 + 自定义 tools 结构性无法经 Builder 聊天帧协议注入。
        known_limitations = [
            "背书边界（已按外部审查收紧措辞）：本用例只背书「Builder 产出的 GenieAPIService "
            "启动参数与进程配置」这条链路（实测命令行含 -l -n -1 -d 3，故 IsStatelessMode() "
            "成立、整条压缩链真实生效），**不**背书 Builder 对这次推理请求有任何介入——"
            "容量池（合成技能 + read 工具）只能向 Builder 拉起的服务端口直发 OpenAI 请求注入，"
            "Builder 自身 conversation 聊天协议无法承载自定义 <available_skills> 与 tools。"
            "证伪判据：Builder 起完服务后立刻 kill Builder 后端，若选对/答对/账本头全部不变，"
            "则连「Builder 启动的服务进程链路」都算过强，实际只背书「Builder 曾启动过该进程」",
            "Builder 侧技能操作（set_skill_run_mode/reload_skills/npu.txt）对本用例的判定"
            "**没有因果影响**（代码事实：本次请求的技能目录全部来自合成容量池，不经 Builder 的"
            "本地技能目录提供者）——保留这三步只为让该 Builder 代码路径真实带电，其功能性验证"
            "不再有独立场景覆盖（原 --suite builder_local_model 的 scenario_a_skill_weather() 已随"
            "该过时套件一并删除，见 test_builder_agent_tasks.py 的真实多轮 agent 测试）。证伪判据："
            "整段删掉这三步，若 Skills-Kept/Total、L2/L1/L0、选对、答对四项全同（token 波动 ≤1%），"
            "则「这三步有影响」被一次证伪",
            f"target_in_builder_log={target_in_builder_log} 的准确解释是「Builder 未参与转发"
            "这次请求」（直发服务端口，Builder 不在链路上），不是「日志缓冲回卷」——按外部审查"
            "更正后不再用后者遮盖；该字段仅作辅助记录，不参与通过判据",
            "X-Genie-Prompt-* 账本头在经 Builder SSE 聊天代理时结构性不可观测（Builder 帧协议"
            f"不透传上游 HTTP 响应头）；本用例因走直发请求而实际观测到 {len(ledger_seen)} 个"
            f"账本字段（{ledger_seen}），按实际观测记录，既不伪造账本断言也不谎称观测不到",
        ]
        if not ev["http_ok"] and (ev.get("error") or "").startswith("round1 请求异常"):
            # 连接层异常（Builder 拉起的服务已消失/端口不通）——属环境/链路问题，
            # 不是「答不对」这个能力结论，精确跳过而不是记假失败。
            all_results.append(_sc_result(
                f"{prefix} N={target_n}", model, False,
                f"经 Builder 的服务端口请求层异常（环境/链路问题，非能力结论）: {ev['error']}",
                skipped=True, data={"evidence": ev, "command": command}))
            return
        passed = bool(ev["picked"] and ev["answered"])
        detail = (f"N={target_n}（与容量池 optimized 收敛前沿同源）；选对={ev['picked']}；"
                  f"答对={ev['answered']}；Skills-Kept/Total={ev['skills_kept']}/{ev['skills_total']}；"
                  f"L2/L1/L0={ev['skills_l2']}/{ev['skills_l1']}/{ev['skills_l0']}；"
                  f"Skills-Budget-Tokens={ev['skills_budget_tokens']}；"
                  f"Tokens-Out/Context={ev['tokens_out']}/{ev['context_size']}；"
                  f"紧急截断={ev['emergency_truncated']}；auth_enabled={auth_enabled}；"
                  f"builder_command={command}；error={ev['error']}；"
                  "已知架构限制: " + " | ".join(known_limitations))
        all_results.append(_sc_result(
            f"{prefix} N={target_n}", model, passed, detail,
            data={"builder_e2e": True, "n": target_n, "evidence": ev,
                  "auth_enabled": auth_enabled, "auth_probe": auth_detail,
                  "builder_command": command, "ledger_headers_observed": ledger_seen,
                  "target_in_builder_log": target_in_builder_log,
                  "known_limitations": known_limitations}))
    except Exception as e:
        detail = (f"Builder 端到端用例未捕获异常（可能 Builder/GenieAPIService 已崩溃）: "
                  f"{type(e).__name__}: {str(e)[:300]}")
        all_results.append(_sc_result(f"{prefix} N={target_n}", model, False, detail))
        all_crash_events.append(CrashEvent(
            timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
            endpoint="skill_capacity_builder_e2e", detail=detail,
            request_history=_trace_snapshot()))
    finally:
        # 还原临时 npu.txt 标记（异常路径同样还原，不残留对 Builder 技能清单的持久改动）
        if npu_marker is not None:
            try:
                npu_marker.unlink(missing_ok=True)
            except OSError:
                pass
        if tester is not None:
            try:
                tester.stop_and_verify(args.port)
            except Exception:
                pass
            try:
                tester.cleanup_junctions()
            except Exception:
                pass
        try:
            builder.stop()
        except Exception:
            pass
        if tester is not None:
            # tester 自身产生的机械记录（configure/inject/discover/start/stop）一并纳入
            # 结果集，precondition 类失败才有可追溯的出处，而不是只剩一句"环境不具备"。
            all_results.extend(tester.results)
            all_crash_events.extend(tester.crash_events)
            # 模型目录安全网：0 违规静默通过（不产生正面记录），违规永不豁免。
            violations = tester.model_dir_snapshot.verify()
            if violations:
                detail = ("模型目录安全网校验失败（Builder 路径），检测到以下违规：\n"
                          + "\n".join(violations))
                print(f"  ✗✗✗ {detail}")
                all_crash_events.append(CrashEvent(
                    timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
                    endpoint="MODEL_DIR_SNAPSHOT", detail=detail))
                all_results.append(TestResult(
                    name=f"{prefix} model_dir_snapshot_verify", round_num=1,
                    model_name=model, passed=False, status_code=0, latency_ms=0,
                    detail=detail, crashed=True, ignorable=False))


def _run_skill_capacity_suite(args, models, remote_mode, out_dir):
    """--suite skill_capacity：二分搜索求两个目标模型（qwen3-8b/qwen2.5_omini）
    「最多能同时装载多少个 skill 且仍能答对」的前沿值。

    `--skill_capacity_mode`：`direct` 只跑直连取证的二分搜索通道（唯一能出前沿数字的通道）；
    `builder` 只跑 `_sc_case_builder_e2e()` 的真实 Builder 端到端确认；`both` 两者都跑
    （Builder 分支先跑，它自管 Builder/服务生命周期并在结束时释放端口）。"""
    all_results = []
    all_crash_events = []
    all_perf_samples = []
    suite_model = "_skill_capacity_"

    if remote_mode:
        all_results.append(_sc_result(
            "SKILL_CAPACITY: suite precondition", suite_model, False,
            "远程模式无法自定义服务命令行（需 -n -1 -g -d 3）也拿不到 stdout 日志，"
            "拿不到启动参数与日志就测不出前沿，按设计精确跳过", skipped=True))
        return all_results, all_perf_samples, all_crash_events

    max_n = getattr(args, "skill_capacity_max", 64)
    repeat = getattr(args, "skill_capacity_repeat", 3)
    timeout = 120

    mode = getattr(args, "skill_capacity_mode", "direct")
    if mode in ("builder", "both"):
        # Builder 真实驱动端到端确认通道（Step 6 落地）：在直连已测出的前沿值上
        # 确认真实 QAIModelBuilder 拉起的 GenieAPIService 同样选对 + 答对。放在直连
        # 二分搜索**之前**跑：它自己完整管理 Builder/服务的启停生命周期，跑完
        # 会把端口释放干净，不与后面每档各自 ServiceManager.start() 的窗口重叠。
        _sc_case_builder_e2e(args, models, all_results, all_crash_events)
        if mode == "builder":
            # 纯 builder 模式不跑直连二分搜索（它是 direct 通道的职责），直接收工。
            return all_results, all_perf_samples, all_crash_events
    arms_arg = getattr(args, "skill_capacity_arms", "legacy")
    arms = ["legacy", "optimized"] if arms_arg == "both" else [arms_arg]

    requested_models = None
    if getattr(args, "skill_capacity_models", None):
        requested_models = {s.strip() for s in args.skill_capacity_models.split(",") if s.strip()}

    targets = []
    m1 = _sc_resolve_model(models, "qwen3-8b")
    if not requested_models or "qwen3-8b" in requested_models:
        if m1:
            targets.append(("qwen3-8b", m1))
        else:
            all_results.append(_sc_result(
                "SKILL_CAPACITY: suite precondition qwen3-8b", suite_model, False,
                f"未在已发现模型中匹配到 qwen3-8b（models={models}），精确跳过", skipped=True))
    m2 = _sc_resolve_multimodal_model(models)
    if not requested_models or "qwen2.5_omini" in requested_models:
        if m2:
            targets.append(("qwen2.5_omini", m2))
        else:
            all_results.append(_sc_result(
                "SKILL_CAPACITY: suite precondition qwen2.5_omini", suite_model, False,
                f"未在已发现模型中匹配到 qwen2.5_omini 四种命名变体之一（models={models}），"
                "精确跳过（不回退到 qwen2.5vl/qwen3_vl，避免假装通过）", skipped=True))

    if not targets:
        all_results.append(_sc_result(
            "SKILL_CAPACITY: suite precondition", suite_model, False,
            "两个目标模型均未匹配到，套件整体精确跳过", skipped=True))
        return all_results, all_perf_samples, all_crash_events

    for short_name, target in targets:
        config_path = Path(args.models) / target / "config.json"
        if not config_path.exists():
            all_results.append(_sc_result(
                f"SKILL_CAPACITY: {short_name} precondition", target, False,
                f"缺失 config.json: {config_path}，精确跳过", skipped=True))
            continue

        for arm in arms:
            print(f"\n{'='*60}")
            print(f"阶段: skill_capacity 二分搜索前沿（模型: {target}, arm={arm}, max_n={max_n}, repeat={repeat}）")
            print(f"{'='*60}")

            wait_port_closed(args.host, args.port, timeout=15)
            svc = ServiceManager(args.exe_dir, args.host, args.port)
            svc._log_dir = args.out_dir
            try:
                with _ScArmConfigOverride(args.exe_dir, arm):
                    svc.start(str(config_path), extra_args=["-n", "-1", "-g", "-d", "3"])
                    if not wait_port_open(args.host, args.port, timeout=180, process=svc.process):
                        all_results.append(_sc_result(
                            f"SKILL_CAPACITY: {short_name} {arm} precondition", target, False,
                            "端口 180s 内未可连接，精确跳过", skipped=True))
                        continue
                    probe = _PromptLogProbe(svc._stdout_log)
                    try:
                        # 场景 4/4b/6（本 Step 计划明确要求的机械断言）先跑：它们不依赖
                        # 二分搜索结果，且两档测量值要进跨档位对照表。场景 4b 是第三轮
                        # 评审要求补齐的「17 工具 Schema -> Tools-Kept 不退化」硬断言。
                        _sc_case_tool_flood_skill_floor(args, target, probe, arm, all_results, timeout)
                        _sc_case_tools_kept_no_regress(args, target, probe, arm, all_results, timeout)
                        _sc_case_chinese_budget(args, target, probe, arm, all_results, timeout)
                        # 场景 2/3（Step3 D4/D2 的机械断言）
                        _sc_case_cn_query_en_pool(args, target, probe, arm, all_results, timeout)
                        _sc_case_disclosure_tiers(args, target, probe, arm, all_results, timeout)
                        # 场景 3b（Step 5 收口）：tie_aware_l2 扩组的最坏情形防护——
                        # 全同分池 N=64 下目录后缀不得被整段丢弃。
                        _sc_case_tie_group_kept_no_regress(args, target, probe, arm,
                                                           all_results, timeout)

                        # Step 5 收口切片：真实前沿数字必须用容量池（目标分数严格最高、
                        # 不存在同分 tie-break）测，不能再用默认的同分池——同分池测出的
                        # 前沿已被证明可能是 tie-break 产物，不反映真实装载容量。
                        frontier, converged, curve = _sc_binary_search(
                            args, target, probe, max_n, repeat, timeout,
                            pool_builder=_sc_build_capacity_pool)
                        # 预算饱和判定（本轮修正第 1(c) 条）：取前沿点对应的曲线条目，
                        # 若该点 skills_kept < skills_total，说明提示词体量已由预算而非 N
                        # 决定，前沿数字与装载能力解耦，**禁止用于计算提升倍数**。
                        frontier_entry = next((e for e in reversed(curve) if e["n"] == frontier), None)
                        saturated = bool(frontier_entry and frontier_entry.get("skills_kept_at_budget_cap"))
                        sat_note = (f"前沿饱和：N={frontier} 处 skills_kept="
                                    f"{frontier_entry.get('skills_kept') if frontier_entry else '?'}"
                                    f" < skills_total={frontier_entry.get('skills_total') if frontier_entry else '?'}"
                                    f"，保留条数由 skills_budget_tokens 决定而非 N，"
                                    f"该数字不得用于算提升倍数") if saturated else None
                        if converged:
                            note = sat_note
                            detail = (f"前沿值({arm})={frontier}（已收敛：N={frontier + 1} 一致失败）；"
                                      f"饱和={saturated}"
                                      + (f"（{sat_note}）" if sat_note else "") +
                                      f"；曲线点数={len(curve)}；末次曲线条目={curve[-1] if curve else None}")
                        else:
                            # 未收敛时携带实际下界，不仅靠 data 字段体现——detail 文案本身
                            # 也必须能独立说清"这是下界不是真实前沿"（本 Step 修正遗留项 a）。
                            note = f"frontier ≥ {frontier}（倍增测试到 max_n={max_n} 仍全部通过，未收敛，需调大 --skill_capacity_max 重测）"
                            if sat_note:
                                note = note + "；" + sat_note
                            detail = (f"frontier_skills≥{frontier}（{note}）；"
                                      f"曲线点数={len(curve)}；末次曲线条目={curve[-1] if curve else None}")
                        # converged=False 或 饱和 时不再走「失败」通道，而是精确记为
                        # skipped=True（上一轮评审采纳项）：这不是「测试失败」，而是
                        # 「该数字不可用于计算提升倍数」的机械信号；把它计作不可豁免失败
                        # 会打破健康判据 failed == ignored 并淹没日后真正的新增失败。
                        # converged/frontier_saturated/usable_for_gain_ratio/probe_curve
                        # 全部 data 字段原样保留，语义不变。
                        usable = bool(converged and not saturated)
                        all_results.append(_sc_result(
                            f"SKILL_CAPACITY: {short_name} {arm}_frontier", target,
                            usable, detail, skipped=not usable,
                            data={"model": target, "arm": arm, "frontier_skills": frontier,
                                  "converged": converged, "frontier_saturated": saturated,
                                  "usable_for_gain_ratio": usable,
                                  "note": note, "probe_curve": curve}))
                        # Step 4：三实验正交定位瓶颈，只在 optimized 档跑一次（legacy 44
                        # 已 converged，本 Step 不重测 legacy，三实验同理只关心 optimized
                        # 的瓶颈成因）。
                        # 探测点**必须取前沿之上的第一个失败点 frontier+1**，不能取前沿本身：
                        # 前沿的定义就是"selection 档在这里通过"，在那里跑三实验必然得到
                        # selection_pass=True → 恒判 none_observed，永远定位不出瓶颈。
                        # 未收敛时（frontier 是下界、上面没有已知失败点）退回 frontier 本身，
                        # 结论会如实落在 none_observed 并标 skipped，不强行归类。
                        if arm == "optimized" and frontier >= 1:
                            probe_n = (frontier + 1) if converged else frontier
                            _sc_run_bottleneck_experiments(args, target, probe, probe_n,
                                                           repeat, timeout, all_results)
                    except Exception as e:
                        detail = f"二分搜索未捕获异常（可能服务已崩溃）: {type(e).__name__}: {str(e)[:300]}"
                        all_results.append(_sc_result(
                            f"SKILL_CAPACITY: {short_name} {arm}_frontier", target, False, detail))
                        all_crash_events.append(CrashEvent(
                            timestamp=datetime.now().isoformat(), model_name=target, round_num=1,
                            endpoint="skill_capacity", detail=detail, request_history=_trace_snapshot()))
            except (RuntimeError, FileNotFoundError) as e:
                all_results.append(_sc_result(
                    f"SKILL_CAPACITY: {short_name} {arm} precondition", target, False,
                    f"服务启动失败: {str(e)[:300]}", skipped=True))
            finally:
                svc.stop()
                svc._force_kill()

        # 两档都跑完后追加跨档位对照断言（D3 开关生效证据 + P1 中文场景真实修复证据）
        if len(arms) >= 2:
            _sc_append_arm_contrast_results(target, all_results)

    return all_results, all_perf_samples, all_crash_events


# ============================================================================
# long_task_memory suite —— Task Memo 分段式记忆机制的"记忆前沿"量化回归
# ============================================================================
# 方法论镜像 skill_capacity 的倍增探测 + 二分收敛 + 重复采样多数票（不直接复用其函数，
# 因签名强耦合技能容量池语义，见 _sc_majority_probe/_sc_binary_search），被测对象换成
# Task Memo（prompt_optimization.task_memo）而非技能目录容量。
#
# 关键架构事实（决定了下面两轮请求的设计，来自对 task_memo_builder.cpp 的代码审查，
# 不是随意选择）：
#   1. ComputeFingerprint 对"除最后一条外的全部非 system 消息"哈希；BuildTaskMemoSection()
#      （系统提示词"## Task Memo"主通道）在 FitMessagesToContext（写库）之前调用——
#      同一个请求内，主通道读到的永远是"上一轮"的旧数据，首次对话必定 MISS。只有
#      FitMessagesToContext 内部丢弃发生后紧跟着的尾部占位兜底 Lookup() 才会在同一
#      请求内命中（RenderCompact，不含 facts_constraints/open_questions 细节）。
#   2. 因此要验证主通道（Render()，携带用户事实/约束/TODO）的真实效果，必须两轮真实
#      请求：Round1 令历史丢弃并写库，Round2（首条 user 消息不变，靠 ComputeFirstMsgKey
#      稳定命中）才会在系统提示词里看到完整备忘录。
#   3. BuildRuleLayer 把 dropped 的单条 user 消息整段存入 facts_constraints（截断到
#      160 字符预览）——若把三项事实塞进同一条长消息，后两项会被截断丢失；因此下面把
#      goal/constraint/todo 拆成三条独立短消息，各自都在 160 字符预览之内。
#
# 记忆前沿定义：模型在 N 个填充轮次（用于挤占预算、诱发丢弃）之后，Round2 追问仍能
# 正确复述任务目标/约束/TODO 三个 canary code 的最大 N。legacy（task_memo.enabled=false）
# 与 optimized（=true，model_layer_enabled=false 保证判定确定性）分别测出前沿，用
# 倍数/差值量化机制收益。
#
# 已更正的架构事实（曾错误记载为"stateful 模式下整条压缩管线不会跑"，这与当前代码不符，
# 不要再假设它成立）：`ChatHistory::Limit()` 全仓库零调用方，是死代码；`model_input_builder.h`
# 驱动的 `PreFilterMessages`/`FitMessagesToContext`/`BuildTaskMemoSection`/`TaskMemoBuilder`
# 整条压缩管线（含 Task Memo）对 `-n` 取 -1 还是正整数完全无分支、无条件执行，两种模式走的
# 是同一条代码路径。`IsStatelessMode()`/`GetEffectiveStatelessMode()` 在全源码中唯一的消费点
# 在 `response_dispatcher.cpp`，只决定客户端断开后服务端是否额外持久化聊天历史——与压缩/
# Task Memo 管线完全无关，本套件的断言不涉及这个分支。stateful 模式因此与 stateless 共享
# 同一套 legacy/optimized 双臂语义，不是"退化为完全等价"的特例。

_LTM_GOAL_CODE = "LTM-GOAL-7F3A1"
_LTM_CONSTRAINT_CODE = "LTM-CONSTRAINT-9B2E4"
_LTM_TODO_CODE = "LTM-TODO-4D8C6"


def _ltm_task_brief_messages():
    """三条各自独立、均在 160 字符预览之内的短消息（原因见模块级注释第 3 点）。"""
    return [
        {"role": "user", "content":
            f"Migration goal ({_LTM_GOAL_CODE}): migrate the billing service from MySQL to PostgreSQL."},
        {"role": "assistant", "content": "Understood, PostgreSQL migration goal noted."},
        {"role": "user", "content":
            f"Hard constraint ({_LTM_CONSTRAINT_CODE}): never modify the file legacy_billing.py; "
            "it is frozen for compliance."},
        {"role": "assistant", "content": "Understood, I will not touch legacy_billing.py."},
        {"role": "user", "content":
            f"TODO ({_LTM_TODO_CODE}): write the migration script for the invoices table."},
        {"role": "assistant", "content": "Noted, invoices table migration script is pending."},
    ]


def _ltm_filler_round(i, lines_per_round):
    """一轮无关闲聊 + 工具调用，用于挤占预算、诱发早期消息被丢弃。"""
    call_id = f"ltm_call_{i}"
    return [
        {"role": "user", "content": f"Status check {i}: please run the next diagnostic step."},
        {"role": "assistant", "content": "", "tool_calls": [
            {"id": call_id, "type": "function",
             "function": {"name": "run_diagnostic", "arguments": json.dumps({"step": i})}}
        ]},
        {"role": "tool", "tool_call_id": call_id, "name": "run_diagnostic",
         "content": _pf_filler_lines(f"ltm{i}", lines_per_round)},
    ]


def _ltm_build_history(n_filler, lines_per_round):
    messages = [
        {"role": "system", "content":
            "You are a careful coding assistant helping with a long-running migration task. "
            "Keep track of every fact, constraint and TODO given earlier in the conversation."},
    ]
    messages.extend(_ltm_task_brief_messages())
    for i in range(n_filler):
        messages.extend(_ltm_filler_round(i, lines_per_round))
    messages.append({"role": "user", "content": "Please just reply 'ack' and nothing else for now."})
    return messages


def _ltm_recall_question():
    return ("Recall this session's task brief. Answer with exactly three lines, quoting the literal "
            "code shown in parentheses for each item: "
            "line 1 = migration goal code, line 2 = constraint code, line 3 = TODO code.")


def _ltm_header_bool(headers, name):
    v = headers.get(name)
    if v is None:
        return None
    return str(v).strip() not in ("0", "", "false", "False")


def _ltm_header_num(headers, name, cast):
    v = headers.get(name)
    if v is None:
        return None
    try:
        return cast(v)
    except ValueError:
        return None


def _ltm_recall_hit(content, canary_code):
    return bool(content) and canary_code.lower() in content.lower()


def _ltm_extract_memo_headers(headers, suffix):
    return {
        f"dropped{suffix}": _ltm_header_num(headers, "X-Genie-Prompt-Messages-Dropped", int),
        f"memo_active{suffix}": _ltm_header_bool(headers, "X-Genie-Prompt-Memo-Active"),
        f"memo_confidence{suffix}": _ltm_header_num(headers, "X-Genie-Prompt-Memo-Confidence", float),
        f"memo_refresh{suffix}": _ltm_header_num(headers, "X-Genie-Prompt-Memo-Refresh-Count", int),
        f"memo_pages{suffix}": _ltm_header_num(headers, "X-Genie-Prompt-Memo-Pages", int),
    }


def _ltm_extract_goal_line(prompt_block):
    """从 `## Task Memo` 渲染文本里取出 `Original goal: ...` 整行（含低置信度后缀），
    抓不到返回 None。"""
    for line in (prompt_block or "").splitlines():
        stripped = line.strip()
        if stripped.startswith("Original goal:"):
            return stripped
    return None


def _ltm_single_trial_direct(args, model, probe, n, lines_per_round, timeout):
    """单次两轮试验（direct 通道）：Round1 制造丢弃并写库，Round2 用相同首条 user
    消息追问三个 canary code，验证是否仍能复述。返回逐字段可诊断的证据字典（供
    --long_task_memory 重跑时定位具体是哪一轮/哪个字段失败，而不仅是聚合统计）。"""
    evidence = {"n": n, "error": None, "trivial": False,
                "recall_goal": False, "recall_constraint": False, "recall_todo": False}
    round1_messages = _ltm_build_history(n, lines_per_round)
    body1 = {"model": model, "stream": False, "messages": round1_messages, "max_tokens": 24}
    _trace_request(model, f"LTM round1 n={n}", 1, "long_task_memory")
    if probe is not None:
        probe.mark()
    try:
        r1 = _pf_post_chat(args.host, args.port, body1, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round1 请求异常（服务可能已崩溃）: {str(e)[:300]}"
        return evidence
    if r1.status_code != 200:
        evidence["error"] = f"round1 HTTP {r1.status_code}: {r1.text[:200]}"
        return evidence
    evidence.update(_ltm_extract_memo_headers(r1.headers, "_r1"))
    evidence["memo_section_in_prompt_r1"] = (
        "## Task Memo" in probe.last_prompt_block()) if probe is not None else None

    if not evidence.get("dropped_r1"):
        # 本次填充量尚未挤出任何历史消息：没有发生压缩事件，记忆机制根本没被触发，
        # 探针天然应当通过（原文仍在上下文里），标注 trivial 供调用方识别 N 过小。
        evidence.update(trivial=True, recall_goal=True, recall_constraint=True, recall_todo=True)
        return evidence

    try:
        msg1 = r1.json()["choices"][0]["message"]
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round1 响应结构异常（无 choices[0].message）"
        return evidence

    round2_messages = round1_messages + [
        {"role": "assistant", "content": msg1.get("content") or "ack"},
        {"role": "user", "content": _ltm_recall_question()},
    ]
    body2 = {"model": model, "stream": False, "messages": round2_messages, "max_tokens": 128}
    _trace_request(model, f"LTM round2 n={n}", 1, "long_task_memory")
    if probe is not None:
        probe.mark()
    try:
        r2 = _pf_post_chat(args.host, args.port, body2, timeout=timeout)
    except Exception as e:
        evidence["error"] = f"round2 请求异常（服务可能已崩溃）: {str(e)[:300]}"
        return evidence
    if r2.status_code != 200:
        evidence["error"] = f"round2 HTTP {r2.status_code}: {r2.text[:200]}"
        return evidence
    evidence.update(_ltm_extract_memo_headers(r2.headers, "_r2"))
    evidence["memo_section_in_prompt_r2"] = (
        "## Task Memo" in probe.last_prompt_block()) if probe is not None else None

    try:
        content2 = r2.json()["choices"][0]["message"].get("content") or ""
    except (KeyError, IndexError, ValueError):
        evidence["error"] = "round2 响应结构异常（无 choices[0].message）"
        return evidence

    evidence["recall_goal"] = _ltm_recall_hit(content2, _LTM_GOAL_CODE)
    evidence["recall_constraint"] = _ltm_recall_hit(content2, _LTM_CONSTRAINT_CODE)
    evidence["recall_todo"] = _ltm_recall_hit(content2, _LTM_TODO_CODE)
    evidence["round2_answer_preview"] = content2[:300]
    return evidence


def _ltm_majority_probe(args, model, probe, n, repeat, lines_per_round, timeout, trial_log):
    trials = [_ltm_single_trial_direct(args, model, probe, n, lines_per_round, timeout)
              for _ in range(max(1, repeat))]
    trial_log.extend(trials)

    def is_pass(t):
        return not t["error"] and t["recall_goal"] and t["recall_constraint"] and t["recall_todo"]

    pass_votes = sum(1 for t in trials if is_pass(t))
    passed = pass_votes * 2 > len(trials)
    last = trials[-1]
    curve_entry = {
        "n": n, "passed": passed, "pass_votes": pass_votes, "trials": len(trials),
        "trivial": last.get("trivial"), "dropped_r1": last.get("dropped_r1"),
        "dropped_r2": last.get("dropped_r2"),
        "memo_active_r1": last.get("memo_active_r1"), "memo_active_r2": last.get("memo_active_r2"),
        "memo_confidence_r2": last.get("memo_confidence_r2"), "memo_refresh_r2": last.get("memo_refresh_r2"),
        "memo_section_in_prompt_r2": last.get("memo_section_in_prompt_r2"),
        "recall_goal": last.get("recall_goal"), "recall_constraint": last.get("recall_constraint"),
        "recall_todo": last.get("recall_todo"), "error": last.get("error"),
    }
    return passed, curve_entry


def _ltm_binary_search(args, model, probe, max_n, repeat, lines_per_round, timeout, trial_log):
    """求最大可通过的 N（记忆前沿），算法与 _sc_binary_search 完全同构（倍增探测找失败
    上界 → 区间二分收敛），如实标注是否真实收敛，避免把未收敛下界误报为真实前沿。"""
    curve = []

    def test(n):
        passed, entry = _ltm_majority_probe(args, model, probe, n, repeat, lines_per_round, timeout, trial_log)
        curve.append(entry)
        return passed

    if not test(1):
        return 0, True, curve

    last_pass, first_fail = 1, None
    n = 2
    while n <= max_n:
        if test(n):
            last_pass = n
            n *= 2
        else:
            first_fail = n
            break

    if first_fail is None:
        return last_pass, False, curve
    if first_fail <= last_pass + 1:
        return last_pass, True, curve

    lo, hi, best = last_pass + 1, first_fail - 1, last_pass
    while lo <= hi:
        mid = (lo + hi) // 2
        if test(mid):
            best = mid
            lo = mid + 1
        else:
            hi = mid - 1
    return best, True, curve


def _ltm_arm_overrides(arm):
    if arm == "legacy":
        return {"enabled": False}
    return {"enabled": True, "model_layer_enabled": False, "min_dropped_for_trigger": 1}


class _LtmArmConfigOverride:
    """临时改写 <exe_dir>/prompt_engineering.json 的 prompt_optimization.task_memo 子节，
    与 _ScArmConfigOverride 同一备份-还原模式（改前备份，__exit__ 里 finally 还原）。"""

    def __init__(self, exe_dir, arm):
        self.config_path = Path(exe_dir) / "prompt_engineering.json"
        self.overrides = _ltm_arm_overrides(arm)
        self._original_text = None
        self._existed = False

    def __enter__(self):
        if self.config_path.exists():
            self._existed = True
            self._original_text = self.config_path.read_text(encoding="utf-8")
            try:
                data = json.loads(self._original_text)
            except Exception:
                data = {}
        else:
            data = {}
        po = data.setdefault("prompt_optimization", {})
        po.setdefault("task_memo", {}).update(self.overrides)
        self.config_path.write_text(json.dumps(data, indent=2, ensure_ascii=False), encoding="utf-8")
        return self

    def __exit__(self, exc_type, exc_val, exc_tb):
        try:
            if self._existed:
                self.config_path.write_text(self._original_text, encoding="utf-8")
            elif self.config_path.exists():
                self.config_path.unlink()
        except Exception as e:
            print(f"WARNING: _LtmArmConfigOverride 还原 {self.config_path} 失败: {e}")
        return False


def _ltm_run_via_client(client_exe, host, port, body, out_dir, timeout):
    """通过 GenieAPIClient.exe --raw_file 发送任意构造的 messages 数组——其正常
    --prompt/--system CLI 每次只能发单轮，--raw_file 分支绕开此限制、原样送出 JSON
    请求体（技法来自 GenieAPIClient.cpp 源码）。返回 (ok, stdout_text)。"""
    raw_dir = Path(out_dir) / "long_task_memory_raw"
    raw_dir.mkdir(parents=True, exist_ok=True)
    raw_path = raw_dir / f"body_{int(time.time() * 1000)}_{random.randint(0, 9999)}.json"
    try:
        raw_path.write_text(json.dumps(body, ensure_ascii=False), encoding="utf-8")
        cmd = [str(client_exe), "--raw_file", str(raw_path), "--host", f"{host}:{port}"]
        proc = subprocess.run(cmd, capture_output=True, text=True, timeout=timeout,
                              encoding="utf-8", errors="replace")
        return proc.returncode == 0, (proc.stdout or "") + (proc.stderr or "")
    except subprocess.TimeoutExpired:
        return False, "TIMEOUT"
    except Exception as e:
        return False, f"EXC: {e}"
    finally:
        try:
            raw_path.unlink()
        except OSError:
            pass


def _ltm_client_spotcheck(args, model, out_dir, n_values, lines_per_round, timeout,
                           all_results, all_crash_events, label, arm, frontier):
    """GenieAPIClient.exe 端到端交叉确认通道：在 direct 通道已求出的前沿附近抽样几个 N，
    用真实客户端可执行文件复核同一 pass/fail 方向，不重跑完整二分搜索（真实进程调用
    开销显著高于 direct HTTP，只做交叉确认而非独立求前沿）。抽样点天然包含 max_n（预期
    召回失败，用于确认前沿之外方向也一致），故按 n<=frontier 期望召回成功/n>frontier 期望
    召回失败分别判定，而非无条件要求召回成功——否则 max_n 点必然被误判为失败。"""
    client_exe = Path(args.exe_dir) / "GenieAPIClient.exe"
    if not client_exe.exists():
        all_results.append(_sc_result(
            f"LONG_TASK_MEMORY: {label}/{arm} client crosscheck", model, False,
            f"未找到 GenieAPIClient.exe: {client_exe}，跳过端到端交叉确认通道", skipped=True))
        return
    for n in n_values:
        round1_messages = _ltm_build_history(n, lines_per_round)
        body1 = {"model": model, "stream": False, "messages": round1_messages, "max_tokens": 24}
        _trace_request(model, f"LTM client round1 n={n}", 1, "long_task_memory")
        try:
            ok1, out1 = _ltm_run_via_client(client_exe, args.host, args.port, body1, out_dir, timeout)
        except Exception as e:
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
                endpoint=f"LTM client round1 n={n}",
                detail=f"long_task_memory client 通道异常: {str(e)[:200]}",
                request_history=_trace_snapshot()))
            ok1, out1 = False, str(e)
        round2_messages = round1_messages + [
            {"role": "assistant", "content": "ack"},
            {"role": "user", "content": _ltm_recall_question()},
        ]
        body2 = {"model": model, "stream": False, "messages": round2_messages, "max_tokens": 128}
        _trace_request(model, f"LTM client round2 n={n}", 1, "long_task_memory")
        ok2, out2 = _ltm_run_via_client(client_exe, args.host, args.port, body2, out_dir, timeout)
        recall = {c: _ltm_recall_hit(out2, c) for c in (_LTM_GOAL_CODE, _LTM_CONSTRAINT_CODE, _LTM_TODO_CODE)}
        expect_recall = n <= frontier
        direction_matches = all(recall.values()) if expect_recall else not all(recall.values())
        passed = ok1 and ok2 and direction_matches
        all_results.append(_sc_result(
            f"LONG_TASK_MEMORY: {label}/{arm} client crosscheck n={n}", model, passed,
            f"GenieAPIClient.exe --raw_file 交叉确认 n={n}: round1_ok={ok1}, round2_ok={ok2}, "
            f"expect_recall={expect_recall}, recall={recall}",
            data={"n": n, "ok1": ok1, "ok2": ok2, "expect_recall": expect_recall, "recall": recall}))


def _ltm_stateful_probe(args, model, probe, n_values, lines_per_round, timeout,
                         all_results, all_crash_events, label, arm):
    """stateful 模式：整条压缩管线（含 TaskMemoBuilder）与 stateless 模式完全同样跑
    （已更正的架构事实见模块级注释：`-n` 只影响客户端断开后是否额外持久化历史，不分支
    压缩/Task Memo 管线），故此函数本质上是——在 `-n` 为正整数的服务实例上重跑一遍
    _ltm_single_trial_direct，验证是否和 stateless 模式走向一致。

    方向感知判定（与 _ltm_client_spotcheck 同构）：round2 每次都重发完整历史，expect_recall 由
    dropped_r2（服务端实际回报的截断量）而非猜测的 n 阈值推导，n 越大只是让 dropped_r2 更大，
    不改变这条因果关系本身。"""
    for n in n_values:
        evidence = _ltm_single_trial_direct(args, model, probe, n, lines_per_round, timeout)
        actual_recall = evidence["recall_goal"] and evidence["recall_constraint"] and evidence["recall_todo"]
        dropped_r2 = evidence.get("dropped_r2")
        if arm == "legacy":
            # legacy 臂（Task Memo 关闭）：丢弃就该召回失败，这是基线对照，预期不变。
            expect_recall = True if dropped_r2 is None else (dropped_r2 == 0)
        else:
            # optimized 臂（Task Memo 开启）：机制的设计目的恰恰是丢弃发生后依然能召回，
            # 不能照搬 legacy 臂"丢弃就该召回失败"的预期。只有在确实发生了丢弃但 Task
            # Memo 根本没激活（memo_active_r2 为假，等同退化为未开启）时，才回退到
            # legacy 同款预期；否则（未丢弃，或丢弃且已激活）预期都是召回成功。
            memo_active_r2 = evidence.get("memo_active_r2")
            if dropped_r2 and not memo_active_r2:
                expect_recall = (dropped_r2 == 0)
            else:
                expect_recall = True
        direction_matches = (actual_recall == expect_recall)
        passed = (not evidence["error"]) and direction_matches
        if evidence["error"] and "异常" in evidence["error"]:
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
                endpoint=f"LTM stateful n={n}", detail=evidence["error"][:200],
                request_history=_trace_snapshot()))
        all_results.append(_sc_result(
            f"LONG_TASK_MEMORY: {label}/stateful/{arm} n={n}", model, passed,
            f"stateful 模式 n={n}: expect_recall={expect_recall}, actual_recall={actual_recall}, {evidence}",
            skipped=bool(evidence.get("trivial")),
            data=evidence))


def _ltm_append_arm_contrast(model, service_mode, frontier_by_arm, all_results):
    legacy_f, opt_f = frontier_by_arm.get("legacy"), frontier_by_arm.get("optimized")
    if legacy_f is None or opt_f is None:
        return
    gain = opt_f - legacy_f
    ratio = (opt_f / legacy_f) if legacy_f > 0 else None
    detail = (f"{service_mode} 模式：legacy frontier={legacy_f}, optimized frontier={opt_f}, 差值={gain}"
              + (f"，倍数={ratio:.2f}x" if ratio is not None else ""))
    all_results.append(_sc_result(
        f"LONG_TASK_MEMORY: {model}/{service_mode} arm_contrast", model, opt_f >= legacy_f, detail,
        data={"legacy_frontier": legacy_f, "optimized_frontier": opt_f, "gain": gain, "ratio": ratio}))


# ============================================================================
# Task Memo 新增字段（goal anchor / failure_streak / 分页目录）轻量回归：场景 A-D
# ============================================================================
# 范围决策（务必保持，不要尝试扩大）：
#   - failure_streak 只做"默认未触发时不出现持久化提示行"的消极回归（见 _ltm_scenario_a_*
#     附带的旁路检查思路——本套件未对它单独建场景，因为该计数器只由
#     response_dispatcher.cpp 的 Layer3 修复路径在真实检测到模型输出畸形 tool_call 时
#     递增，HTTP 请求无法可靠构造触发；强行构造是非确定性且模型相关的，不值得做）。
#   - 分页目录只验证"计数器连通性"（存在/非负/不下降），不追打 max_entries=20 的 FIFO
#     淘汰：每次 Update() 都绑定一整轮真实推理，20+ 轮在真机上成本过高。
#   - 流式 SSE 帧里的 memo_pages_total 不做断言：现有套件没有现成的流式帧解析脚手架，
#     为这一个字段新搭一套的成本不划算，非流式响应头已经能验证管线连通。


def _ltm_new_fields_models(args):
    """返回 Task Memo 新增字段回归（场景 A-D）要跑的模型简写集合，默认仅 qwen3-8b
    （控制真机推理成本——这组场景不求前沿数字，但每个场景仍需 1-4 轮额外真实推理）。"""
    raw = getattr(args, "long_task_memory_new_fields_models", None)
    if not raw:
        return {"qwen3-8b"}
    return {s.strip() for s in raw.split(",") if s.strip()}


def _ltm_scenario_a_goal_anchor_persist(args, model, probe, lines_per_round, timeout,
                                        all_results, all_crash_events, label):
    """场景 A：开场夹杂低于 20 字符门槛的闲聊时，goal anchor 必须锚定在真正的任务目标
    消息（而非闲聊）；二次丢弃事件后锚文本必须逐字节不变（"一次捕获，永不覆盖"）。"""
    name = f"LONG_TASK_MEMORY: {label}/goal_anchor_persist"
    system_msg = {"role": "system", "content":
                  "You are a careful coding assistant helping with a long-running migration task. "
                  "Keep track of every fact, constraint and TODO given earlier in the conversation."}
    smalltalk = [
        {"role": "user", "content": "你好"},
        {"role": "assistant", "content": "你好，有什么可以帮你？"},
        {"role": "user", "content": "hi"},
        {"role": "assistant", "content": "hi there"},
    ]
    base_messages = [system_msg] + smalltalk + _ltm_task_brief_messages()
    max_probe = getattr(args, "long_task_memory_max", 8)

    def _round(n_filler):
        msgs = list(base_messages)
        for i in range(n_filler):
            msgs.extend(_ltm_filler_round(i, lines_per_round))
        msgs.append({"role": "user", "content": "Please just reply 'ack' and nothing else for now."})
        body = {"model": model, "stream": False, "messages": msgs, "max_tokens": 24}
        _trace_request(model, f"LTM scenario_a n={n_filler}", 1, "long_task_memory")
        probe.mark()
        try:
            r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
        except Exception as e:
            return None, None, f"请求异常: {str(e)[:300]}"
        if r.status_code != 200:
            return None, None, f"HTTP {r.status_code}: {r.text[:200]}"
        return r, probe.last_prompt_block(), None

    r1 = prompt1 = err = None
    n_used = None
    for n in range(1, max_probe + 1):
        r1, prompt1, err = _round(n)
        if err:
            break
        if r1.headers.get("X-Genie-Prompt-Messages-Dropped") not in (None, "0"):
            n_used = n
            break
    if err:
        all_results.append(_sc_result(name, model, False, err, skipped=True))
        return
    if n_used is None:
        all_results.append(_sc_result(
            name, model, False,
            f"倍增到 --long_task_memory_max={max_probe} 仍未触发任何丢弃事件，无法验证 goal anchor，精确跳过",
            skipped=True))
        return

    # BuildTaskMemoSection() 渲染正文发生在 FitMessagesToContext 写库之前：刚触发丢弃
    # 的那一轮（n_used）自己读到的仍是写库前的旧正文，必须再追加一轮才能读到刚写入的
    # goal anchor。响应头没有这个延迟，但本场景只关心正文渲染，所以统一改用追加轮。
    r_a, prompt_a, err_a = _round(n_used + 1)
    if err_a:
        all_results.append(_sc_result(f"{name}/round1", model, False, err_a, skipped=True))
        return
    goal_line1 = _ltm_extract_goal_line(prompt_a)
    ok1 = bool(goal_line1) and _LTM_GOAL_CODE in goal_line1 and "(low confidence:" not in goal_line1
    all_results.append(_sc_result(
        f"{name}/round1", model, ok1,
        f"n_filler={n_used} 触发首次丢弃，追加一轮（n_filler={n_used + 1}）读正文后 goal anchor: {goal_line1!r}",
        data={"goal_line": goal_line1, "n_filler": n_used}))
    if not ok1:
        return

    r2, prompt2, err2 = _round(n_used + 2)
    if err2:
        all_results.append(_sc_result(f"{name}/round2_unchanged", model, False, err2, skipped=True))
        return
    goal_line2 = _ltm_extract_goal_line(prompt2)
    ok2 = goal_line2 == goal_line1
    all_results.append(_sc_result(
        f"{name}/round2_unchanged", model, ok2,
        f"再追加一轮（n_filler={n_used + 2}）后 goal anchor 是否逐字节不变: round1={goal_line1!r}, round2={goal_line2!r}",
        data={"goal_line1": goal_line1, "goal_line2": goal_line2}))


def _ltm_scenario_b_goal_anchor_low_confidence(args, model, probe, lines_per_round, timeout,
                                               all_results, all_crash_events, label):
    """场景 B：开场 goal_scan_window（默认 3）条 user 消息全部低于 20 字符门槛时，
    goal anchor 必须回退到第一条 user 消息并带低置信度后缀——纯规则性回归，不涉及
    模型判断本身。"""
    name = f"LONG_TASK_MEMORY: {label}/goal_anchor_low_confidence"
    system_msg = {"role": "system", "content":
                  "You are a careful coding assistant helping with a long-running migration task."}
    shorts = [
        {"role": "user", "content": "ok"},
        {"role": "assistant", "content": "ok"},
        {"role": "user", "content": "hi"},
        {"role": "assistant", "content": "hi"},
        {"role": "user", "content": "go"},
        {"role": "assistant", "content": "go"},
    ]
    base_messages = [system_msg] + shorts
    max_probe = getattr(args, "long_task_memory_max", 8)

    def _round(n_filler):
        msgs = list(base_messages)
        for i in range(n_filler):
            msgs.extend(_ltm_filler_round(i, lines_per_round))
        msgs.append({"role": "user", "content": "Please just reply 'ack' and nothing else for now."})
        body = {"model": model, "stream": False, "messages": msgs, "max_tokens": 24}
        _trace_request(model, f"LTM scenario_b n={n_filler}", 1, "long_task_memory")
        probe.mark()
        try:
            r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
        except Exception as e:
            return None, None, f"请求异常: {str(e)[:300]}"
        if r.status_code != 200:
            return None, None, f"HTTP {r.status_code}: {r.text[:200]}"
        return r, probe.last_prompt_block(), None

    n_used = None
    for n in range(1, max_probe + 1):
        r, prompt, err = _round(n)
        if err:
            all_results.append(_sc_result(name, model, False, err, skipped=True))
            return
        if r.headers.get("X-Genie-Prompt-Messages-Dropped") not in (None, "0"):
            n_used = n
            break
    if n_used is None:
        all_results.append(_sc_result(
            name, model, False,
            f"倍增到 --long_task_memory_max={max_probe} 仍未触发任何丢弃事件，无法验证低置信度回退，精确跳过",
            skipped=True))
        return

    # 同场景 A 的根因：正文渲染发生在写库之前，刚触发丢弃的那一轮自己读不到刚写入的
    # 内容，必须再追加一轮才能读到低置信度回退后的 goal anchor。
    r_after, prompt_after, err_after = _round(n_used + 1)
    if err_after:
        all_results.append(_sc_result(name, model, False, err_after, skipped=True))
        return
    goal_line = _ltm_extract_goal_line(prompt_after)
    ok = bool(goal_line) and "ok" in goal_line.lower() and "(low confidence:" in goal_line
    all_results.append(_sc_result(
        name, model, ok,
        f"n_filler={n_used} 触发丢弃，追加一轮（n_filler={n_used + 1}）读正文后低置信度回退 goal anchor: {goal_line!r}",
        data={"goal_line": goal_line, "n_filler": n_used}))


def _ltm_scenario_c_page_directory(args, model, probe, lines_per_round, timeout,
                                   all_results, all_crash_events, label):
    """场景 C：分页目录（`pages`/`memo_pages_total`）管线连通性——只验证响应头存在/
    非负/不下降，以及渲染区不泄漏原始填充文本，不追打 max_entries=20 的 FIFO 淘汰
    （见模块级范围决策注释）。"""
    name = f"LONG_TASK_MEMORY: {label}/page_directory"
    system_msg = {"role": "system", "content":
                  "You are a careful coding assistant helping with a long-running migration task. "
                  "Keep track of every fact, constraint and TODO given earlier in the conversation."}
    messages = [system_msg] + _ltm_task_brief_messages()
    distinctive_filler_substr = "routine progress record"
    max_probe = getattr(args, "long_task_memory_max", 8)
    pages_seen = []
    i = 0
    rounds_done = 0
    while rounds_done < 3 and i < max_probe * 2:
        messages = messages + _ltm_filler_round(i, lines_per_round)
        i += 1
        probe_msgs = messages + [{"role": "user", "content": "Please just reply 'ack' and nothing else for now."}]
        body = {"model": model, "stream": False, "messages": probe_msgs, "max_tokens": 24}
        _trace_request(model, f"LTM scenario_c round={rounds_done}", 1, "long_task_memory")
        probe.mark()
        try:
            r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
        except Exception as e:
            all_results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}", skipped=True))
            return
        if r.status_code != 200:
            all_results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}", skipped=True))
            return
        if r.headers.get("X-Genie-Prompt-Messages-Dropped") in (None, "0"):
            continue
        # 响应头是本轮 Update() 调用的即时返回值，不受正文渲染延迟影响，可以在循环内
        # 直接读取；正文（section_ok）必须延后到循环结束后再追加一轮读取，见下方。
        pages_total = _ltm_header_num(r.headers, "X-Genie-Prompt-Memo-Pages", int)
        pages_seen.append(pages_total)
        rounds_done += 1
    if not pages_seen or any(p is None for p in pages_seen):
        all_results.append(_sc_result(
            name, model, False,
            f"X-Genie-Prompt-Memo-Pages 头缺失，或在 --long_task_memory_max={max_probe} 的 2 倍探测窗口内"
            f"未能触发 3 轮丢弃事件: pages_seen={pages_seen}", skipped=True))
        return

    # 正文渲染（## Task Memo 的 Evicted message pages 小节）比写库晚一轮：上面 3 轮
    # 丢弃事件各自读到的都是写库前的旧正文，必须再追加一轮才能读到最新一次写入的内容。
    messages = messages + _ltm_filler_round(i, lines_per_round)
    probe_msgs = messages + [{"role": "user", "content": "Please just reply 'ack' and nothing else for now."}]
    body = {"model": model, "stream": False, "messages": probe_msgs, "max_tokens": 24}
    _trace_request(model, "LTM scenario_c read_section", 1, "long_task_memory")
    probe.mark()
    try:
        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
    except Exception as e:
        all_results.append(_sc_result(name, model, False, f"请求异常: {str(e)[:300]}", skipped=True))
        return
    if r.status_code != 200:
        all_results.append(_sc_result(name, model, False, f"HTTP {r.status_code}: {r.text[:200]}", skipped=True))
        return
    prompt_block = probe.last_prompt_block()
    has_section = "Evicted message pages" in prompt_block
    # 分页目录块按设计是 Render() 里最低优先级、预算紧张时可被整块丢弃的小节（见
    # task_memo_builder.md「分页目录」条目）——真机实测过（2026-10-07，filler_lines=20
    # 的激进探测参数）该块确实会被整体省略，这是设计内行为，不是泄漏/缺陷。因此"未泄漏
    # 原文"只在该块确实渲染出来时才有意义去检查；块本身整体缺失时无从泄漏，视为空洞为真。
    tail = prompt_block.split("Evicted message pages", 1)[-1] if has_section else ""
    no_leak = (distinctive_filler_substr not in tail) if has_section else True

    non_negative = all(p >= 0 for p in pages_seen)
    non_decreasing = all(pages_seen[j] <= pages_seen[j + 1] for j in range(len(pages_seen) - 1))
    strictly_increasing_by_one = all(pages_seen[j + 1] - pages_seen[j] == 1 for j in range(len(pages_seen) - 1))
    passed = non_negative and non_decreasing and no_leak
    detail = (f"pages_seen={pages_seen}（non_negative={non_negative}, non_decreasing={non_decreasing}, "
              f"strictly_increasing_by_1_per_drop={strictly_increasing_by_one}——仅观测记录，未强制断言此项）；"
              f"has_section={has_section}（False 时视为预算过紧导致该最低优先级块被整体丢弃，设计内行为，"
              f"不计入失败）；no_leak={no_leak}")
    all_results.append(_sc_result(name, model, passed, detail,
                                  data={"pages_seen": pages_seen, "has_section": has_section, "no_leak": no_leak}))


def _ltm_run_new_field_scenarios(args, model, probe, lines_per_round, timeout,
                                 all_results, all_crash_events, label):
    """新增字段场景 A/B/C 的统一入口，复用调用方已启动的 optimized/stateless 服务实例，
    单个场景异常不中断另外两个（各自独立 try/except 记 CrashEvent）。"""
    for fn, tag in (
        (_ltm_scenario_a_goal_anchor_persist, "scenario_a"),
        (_ltm_scenario_b_goal_anchor_low_confidence, "scenario_b"),
        (_ltm_scenario_c_page_directory, "scenario_c"),
    ):
        try:
            fn(args, model, probe, lines_per_round, timeout, all_results, all_crash_events, label)
        except Exception as e:
            all_crash_events.append(CrashEvent(
                timestamp=datetime.now().isoformat(), model_name=model, round_num=1,
                endpoint=f"LTM {tag}/{label}", detail=f"{tag} 执行异常: {str(e)[:200]}",
                request_history=_trace_snapshot()))


def _ltm_scenario_d_mode_consistency(args, label, target, config_path, lines_per_round, timeout,
                                     out_dir, all_results, all_crash_events, stateful_n):
    """场景 D：用户明确要求的回归点——`-n` 取 -1（stateless）或正整数（stateful）时，
    压缩管线（含 Task Memo 新增字段）必须走完全相同的路径。依次（非并发）起两个服务
    实例喂同一份历史，比较 goal anchor 文本与 memo_pages_total 的出现情况是否一致。"""
    name_prefix = f"LONG_TASK_MEMORY: {label}/mode_consistency"
    max_probe = getattr(args, "long_task_memory_max", 8)

    def _run_one(service_mode):
        wait_port_closed(args.host, args.port, timeout=15)
        svc = ServiceManager(args.exe_dir, args.host, args.port)
        svc._log_dir = out_dir
        extra_args = ["-n", "-1", "-g", "-d", "3"] if service_mode == "stateless" \
            else ["-n", str(stateful_n), "-g", "-d", "3"]
        try:
            with _LtmArmConfigOverride(args.exe_dir, "optimized"):
                svc.start(str(config_path), extra_args=extra_args)
                if not wait_port_open(args.host, args.port, timeout=180, process=svc.process):
                    return None, f"{service_mode} 服务 180s 内未可连接"
                probe = _PromptLogProbe(svc._stdout_log)

                def _send(n_filler):
                    history = _ltm_build_history(n_filler, lines_per_round)
                    body = {"model": target, "stream": False, "messages": history, "max_tokens": 24}
                    probe.mark()
                    _trace_request(target, f"LTM mode_consistency {service_mode} n={n_filler}", 1,
                                    "long_task_memory")
                    try:
                        r = _pf_post_chat(args.host, args.port, body, timeout=timeout)
                    except Exception as e:
                        return None, None, f"{service_mode} 请求异常: {str(e)[:300]}"
                    if r.status_code != 200:
                        return None, None, f"{service_mode} HTTP {r.status_code}: {r.text[:200]}"
                    return r, probe.last_prompt_block(), None

                # 硬编码固定 n_filler 不保证真的触发丢弃（是否挤占预算全看实际 token 占用）：
                # 改为像场景 A/B 一样循环探测，直到观测到丢弃事件为止。
                n_used = None
                r = prompt = err = None
                for n in range(1, max_probe + 1):
                    r, prompt, err = _send(n)
                    if err:
                        return None, err
                    if r.headers.get("X-Genie-Prompt-Messages-Dropped") not in (None, "0"):
                        n_used = n
                        break
                if n_used is None:
                    return None, (f"{service_mode} 倍增到 --long_task_memory_max={max_probe} "
                                   f"仍未触发任何丢弃事件")

                # 正文渲染晚一轮、响应头本轮即时准确：两边统一改用追加轮的数值，保持口径
                # 一致，便于跨模式比较（而不是一个用本轮头、一个用追加轮正文）。
                r_after, prompt_after, err_after = _send(n_used + 1)
                if err_after:
                    return None, err_after
                evidence = {
                    "n_filler_used": n_used,
                    "dropped": _ltm_header_num(r_after.headers, "X-Genie-Prompt-Messages-Dropped", int),
                    "memo_pages_total": _ltm_header_num(r_after.headers, "X-Genie-Prompt-Memo-Pages", int),
                    "goal_line": _ltm_extract_goal_line(prompt_after),
                }
                return evidence, None
        except (RuntimeError, FileNotFoundError) as e:
            return None, f"{service_mode} 服务启动失败: {str(e)[:300]}"
        finally:
            svc.stop()
            svc._force_kill()

    evidence_stateless, err_stateless = _run_one("stateless")
    if err_stateless:
        all_results.append(_sc_result(f"{name_prefix} precondition", target, False, err_stateless, skipped=True))
        return
    evidence_stateful, err_stateful = _run_one("stateful")
    if err_stateful:
        all_results.append(_sc_result(f"{name_prefix} precondition", target, False, err_stateful, skipped=True))
        return

    goal_consistent = (bool(evidence_stateless["goal_line"]) and bool(evidence_stateful["goal_line"])
                       and evidence_stateless["goal_line"] == evidence_stateful["goal_line"])
    pages_consistent = (evidence_stateless["memo_pages_total"] is not None
                        and evidence_stateful["memo_pages_total"] is not None)
    passed = goal_consistent and pages_consistent
    all_results.append(_sc_result(
        name_prefix, target, passed,
        f"stateless={evidence_stateless}, stateful={evidence_stateful}；"
        f"goal_consistent={goal_consistent}, pages_consistent={pages_consistent}",
        data={"stateless": evidence_stateless, "stateful": evidence_stateful}))


def _run_long_task_memory_suite(args, models, remote_mode, out_dir):
    """--suite long_task_memory：Task Memo 分段式记忆机制的「记忆前沿」量化回归。

    核心指标：模型在 N 次压缩/丢弃事件之后，Round2 追问仍能复述任务目标/约束/TODO
    三个 canary code 的最大 N（倍增探测 + 二分收敛 + 重复采样多数票，方法论同构
    skill_capacity，见模块级注释）。legacy（task_memo 关闭）vs optimized（开启）
    双臂对照量化机制收益；direct（Python 直连读 X-Genie-Prompt-Memo-* 头）与
    GenieAPIClient.exe（--raw_file 端到端交叉确认）双通道。stateful 模式下压缩管线与
    stateless 完全同样跑，同样做 legacy/optimized 双臂对照（已更正的架构事实见模块级
    注释，见 _ltm_stateful_probe）。

    仅实现 Tier 1（合成长任务 + 宽松文本记忆探针）。Tier 2（基于 tool_calls 协议的多步骤
    编码任务端到端核验）本轮未实现：它要求服务端维护一份独立于 Task Memo 的 ground-truth
    环境状态机（文件系统/构建产物的期望值）来核验任务是否真正完成，工作量与真机测试时间
    预算不匹配，按计划 Testing 部分"工作量过大则明确记录跳过原因"处理，跳过。

    本套件中还挂着 Task Memo 新增字段（goal anchor/分页目录/跨模式一致性）的两组
    轻量回归：场景 A/B/C（_ltm_run_new_field_scenarios）复用本循环已启动的
    optimized/stateless 实例，场景 D（_ltm_scenario_d_mode_consistency）自己管理一对
    stateless/stateful 实例生命周期。默认只对 --long_task_memory_new_fields_models
    命中的模型（默认仅 qwen3-8b）跑，控制真机推理成本。
    """
    all_results, all_perf_samples, all_crash_events = [], [], []
    suite_model = "_long_task_memory_"

    if remote_mode:
        all_results.append(_sc_result(
            "LONG_TASK_MEMORY: suite precondition", suite_model, False,
            "远程模式无法自定义服务命令行（stateless 需 -n -1，stateful 需自定义 -n）也无法临时改写 "
            "prompt_engineering.json 切换 legacy/optimized 档位，跳过记忆前沿套件", skipped=True))
        return all_results, all_perf_samples, all_crash_events

    requested = None
    if getattr(args, "long_task_memory_models", None):
        requested = {s.strip() for s in args.long_task_memory_models.split(",") if s.strip()}

    targets = []
    m1 = _sc_resolve_model(models, "qwen3-8b")
    if not requested or "qwen3-8b" in requested:
        if m1:
            targets.append(("qwen3-8b", m1))
        else:
            all_results.append(_sc_result(
                "LONG_TASK_MEMORY: suite precondition qwen3-8b", suite_model, False,
                f"未在已发现模型中匹配到 qwen3-8b（models={models}），精确跳过", skipped=True))
    m2 = next((m for m in models if infer_backend(m)[0] == "GGUF"), None)
    if not requested or "gguf-20b" in requested:
        if m2:
            targets.append(("gguf-20b", m2))
        else:
            all_results.append(_sc_result(
                "LONG_TASK_MEMORY: suite precondition gguf-20b", suite_model, False,
                f"未在已发现模型中匹配到任何 GGUF 后端模型（models={models}），精确跳过", skipped=True))
    m3 = next((m for m in models if infer_backend(m)[0] == "mnn"), None)
    if not requested or "mnn-20b" in requested:
        if m3:
            targets.append(("mnn-20b", m3))
        else:
            all_results.append(_sc_result(
                "LONG_TASK_MEMORY: suite precondition mnn-20b", suite_model, False,
                f"未在已发现模型中匹配到任何 MNN 后端模型（models={models}），精确跳过", skipped=True))

    if not targets:
        return all_results, all_perf_samples, all_crash_events

    max_n = getattr(args, "long_task_memory_max", 8)
    repeat = getattr(args, "long_task_memory_repeat", 1)
    lines_per_round = getattr(args, "long_task_memory_filler_lines", 6)
    timeout = getattr(args, "long_task_memory_timeout", 180)
    arms = ("legacy", "optimized") if getattr(args, "long_task_memory_arms", "both") == "both" \
        else (args.long_task_memory_arms,)
    drive_modes = ("direct", "client") if getattr(args, "long_task_memory_mode", "direct") == "both" \
        else (getattr(args, "long_task_memory_mode", "direct"),)
    service_modes = ("stateless", "stateful") if getattr(args, "long_task_memory_service_mode", "stateless") == "both" \
        else (getattr(args, "long_task_memory_service_mode", "stateless"),)
    stateful_n = getattr(args, "long_task_memory_stateful_n", 6)
    new_fields_targets = _ltm_new_fields_models(args)

    for label, target in targets:
        config_path = Path(args.models) / target / "config.json"
        if not config_path.exists():
            all_results.append(_sc_result(
                f"LONG_TASK_MEMORY: {label} precondition", target, False,
                f"缺失 config.json: {config_path}，精确跳过", skipped=True))
            continue

        for service_mode in service_modes:
            arms_for_mode = arms if service_mode == "stateless" else ("optimized",)
            frontier_by_arm = {}
            for arm in arms_for_mode:
                print(f"\n{'='*60}")
                print(f"阶段: long_task_memory（模型={label}/{target}, service_mode={service_mode}, arm={arm}）")
                print(f"{'='*60}")

                wait_port_closed(args.host, args.port, timeout=15)
                svc = ServiceManager(args.exe_dir, args.host, args.port)
                svc._log_dir = out_dir
                extra_args = ["-n", "-1", "-g", "-d", "3"] if service_mode == "stateless" \
                    else ["-n", str(stateful_n), "-g", "-d", "3"]
                try:
                    with _LtmArmConfigOverride(args.exe_dir, arm):
                        svc.start(str(config_path), extra_args=extra_args)
                        if not wait_port_open(args.host, args.port, timeout=180, process=svc.process):
                            all_results.append(_sc_result(
                                f"LONG_TASK_MEMORY: {label}/{service_mode}/{arm} precondition",
                                target, False, "端口 180s 内未可连接，精确跳过", skipped=True))
                            continue
                        probe = _PromptLogProbe(svc._stdout_log)
                        if service_mode == "stateless" and arm == "optimized" and label in new_fields_targets:
                            # Task Memo 新增字段（goal anchor/分页目录）的轻量回归，复用本次
                            # 已启动的 optimized/stateless 实例，不额外起停服务（见 _ltm_run_new_field_scenarios）。
                            _ltm_run_new_field_scenarios(args, target, probe, lines_per_round, timeout,
                                                         all_results, all_crash_events, label)
                        trial_log = []
                        if service_mode == "stateless":
                            if "direct" in drive_modes:
                                frontier, converged, curve = _ltm_binary_search(
                                    args, target, probe, max_n, repeat, lines_per_round, timeout, trial_log)
                                frontier_by_arm[arm] = frontier
                                # memory_probe_accuracy：把二分搜索过程中触达的全部 N 的
                                # pass_votes/trials 聚合成一个具名准确率，与离散的 frontier
                                # 数字互补（frontier 只反映边界，accuracy 反映边界附近整体稳定性）。
                                total_votes = sum(c.get("pass_votes", 0) for c in curve)
                                total_trials = sum(c.get("trials", 0) for c in curve)
                                memory_probe_accuracy = (total_votes / total_trials) if total_trials else None
                                note = (f"前沿值({arm})={frontier}（已收敛）" if converged else
                                        f"frontier ≥ {frontier}（倍增到 max_n={max_n} 仍全部通过，未收敛，"
                                        f"需调大 --long_task_memory_max 重测）")
                                acc_str = f"{memory_probe_accuracy:.2f}" if memory_probe_accuracy is not None else "N/A"
                                all_results.append(_sc_result(
                                    f"LONG_TASK_MEMORY: {label}/{service_mode}/{arm} frontier", target,
                                    converged, note + f"；memory_probe_accuracy={acc_str}；曲线点数={len(curve)}；"
                                    f"末次曲线条目={curve[-1] if curve else None}", skipped=not converged,
                                    data={"model": target, "arm": arm, "frontier": frontier,
                                          "converged": converged, "probe_curve": curve,
                                          "memory_probe_accuracy": memory_probe_accuracy,
                                          "trials": trial_log}))
                            if "client" in drive_modes:
                                spot_ns = sorted(set(
                                    n for n in (1, max(1, frontier_by_arm.get(arm, 1)), max_n) if n >= 1
                                )) if "direct" in drive_modes else sorted({1, max_n})
                                _ltm_client_spotcheck(args, target, out_dir, spot_ns, lines_per_round,
                                                      timeout, all_results, all_crash_events, label, arm,
                                                      frontier_by_arm.get(arm, 1))
                        else:
                            spot_ns = sorted(set(n for n in (1, max(1, stateful_n // 2), stateful_n + 2) if n >= 1))
                            _ltm_stateful_probe(args, target, probe, spot_ns, lines_per_round, timeout,
                                               all_results, all_crash_events, label, arm)
                except (RuntimeError, FileNotFoundError) as e:
                    all_results.append(_sc_result(
                        f"LONG_TASK_MEMORY: {label}/{service_mode}/{arm} precondition", target, False,
                        f"服务启动失败: {str(e)[:300]}", skipped=True))
                except Exception as e:
                    all_crash_events.append(CrashEvent(
                        timestamp=datetime.now().isoformat(), model_name=target, round_num=1,
                        endpoint=f"LTM {service_mode}/{arm}", detail=f"套件执行异常: {str(e)[:200]}",
                        request_history=_trace_snapshot()))
                finally:
                    svc.stop()
                    svc._force_kill()

            if service_mode == "stateless" and len(frontier_by_arm) >= 2:
                _ltm_append_arm_contrast(target, service_mode, frontier_by_arm, all_results)

        if label in new_fields_targets:
            # 场景 D：`-n` -1 与正整数两模式的新字段一致性回归，自己管理服务实例生命周期，
            # 不复用上述循环的服务实例（它需要同时对比两种 service_mode）。
            _ltm_scenario_d_mode_consistency(args, label, target, config_path, lines_per_round, timeout,
                                             out_dir, all_results, all_crash_events, stateful_n)

    return all_results, all_perf_samples, all_crash_events


SUITE_HANDLERS = {
    "full": _run_full_suite,
    "model": _run_model_suite,
    "sampleapp": _run_sampleapp_suite,
    "multimodal": _run_multimodal_suite,
    "gguf": _run_gguf_suite,
    "multi_model": _run_multi_model_suite,
    "mnn": _run_mnn_suite,
    "qnn": _run_qnn_suite,
    "graceful_shutdown": _run_graceful_shutdown_suite,
    "prompt_fidelity": _run_prompt_fidelity_suite,
    "skill_capacity": _run_skill_capacity_suite,
    "long_task_memory": _run_long_task_memory_suite,
}


def main():
    parser = argparse.ArgumentParser(
        description="GenieAPIService 集成测试脚本 - 全自动测试所有 API 接口",
        formatter_class=argparse.RawDescriptionHelpFormatter,
        epilog="""
注意: --suite 为必传参数，不再有隐式默认值；如需运行完整回归请显式传入 --suite full。

示例:
    # 完整回归（本地模式，自动启动/停止服务）:
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite full
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite full --rounds 5 --port 9000

    # 远程模式（连接已运行的服务）:
    python test_service.py --remote --host 10.92.140.91 --port 8910 --suite full
    python test_service.py --remote --host 10.92.140.91 --port 8910 --suite model --rounds 1

    # 按套件精确运行:
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite sampleapp
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite gguf --gguf_devices gpu
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite gguf --gguf_devices gpu,cpu,npu,npu+gpu
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite mnn
    python test_service.py --exe_dir ./GenieService_v2.3.7 --models ./models --suite qnn
        """
    )
    parser.add_argument("--exe_dir", default=None, help="GenieAPIService.exe 所在目录（本地模式必填）")
    parser.add_argument("--models", default=None, help="模型根目录（本地模式必填，每个子目录含 config.json）")
    parser.add_argument("--remote", action="store_true", help="远程模式：连接已运行的服务，不启动/停止进程")
    parser.add_argument("--out_dir", default="./test_results", help="输出目录（默认 ./test_results）")
    parser.add_argument("--host", default="127.0.0.1", help="服务地址（默认 127.0.0.1）")
    parser.add_argument("--port", type=int, default=8910, help="服务端口（默认 8910）")
    parser.add_argument("--rounds", type=int, default=1, help="每个模型的测试轮数（默认 1）")
    parser.add_argument("--multimodal_rounds", type=int, default=None,
                        help="图片/音频多模态用例（含动态切换稳定性用例）的独立执行轮数，优先级高于 --rounds（默认跟随 --rounds）")
    parser.add_argument("--data_dir", default=r"C:\Users\HCKTest\Desktop\GenieEnv\data",
                        help="多模态素材根目录，含 img/ 与 audio/ 子目录（默认 C:\\Users\\HCKTest\\Desktop\\GenieEnv\\data）")
    parser.add_argument("--builder_dir", default="./QAIModelBuilder", help="QAIModelBuilder 根目录（默认 ./QAIModelBuilder）")
    parser.add_argument("--builder_port", type=int, default=8989, help="QAIModelBuilder 后端端口（默认 8989）")
    parser.add_argument("--builder_python", default=None,
                        help="QAIModelBuilder 使用的 python.exe（默认自动探测官方 Setup.bat 搭建的独立 venv："
                             "%%LOCALAPPDATA%%\\QAIModelBuilder\\envs\\.venv_arm64_313\\Scripts\\python.exe，"
                             "找不到则回退当前 sys.executable 并打印警告）")
    parser.add_argument("--builder_data_dir", default=None,
                        help="QAIModelBuilder 隔离数据目录（QAI_DATA__DATA_DIR），默认 <out_dir>/qaimodelbuilder_data，"
                             "每次运行新建、非持久；如需复用/持久化可显式传入固定路径")
    parser.add_argument("--genie_root_path", default=None,
                        help="供 QAIModelBuilder 使用的 GenieAPIService 安装目录（通过 mklink /J 联接到 "
                             "<data_dir>/bin/<name> 以触发 Builder 官方自愈式安装发现），默认复用 --exe_dir。"
                             "供 skill_capacity 的 builder 模式使用")
    parser.add_argument("--gguf_model", default=None, help="GGUF 显式加载回归限定的单个模型目录名（默认留空，测试全部已发现的 GGUF 模型）")
    parser.add_argument("--gguf_devices", type=parse_gguf_devices, default=parse_gguf_devices("both"),
                        help="GGUF 显式加载回归的设备组合，逗号分隔，多设备用 + 连接：gpu,cpu,npu,npu+gpu（both 等价于 gpu,cpu，默认 both）；"
                             "gpu/cpu 走旧 device 字段，含 npu 的组合走 devices 列表，构建无 Hexagon 或 HTP0 未注册时 npu 降级仍判通过并在 detail 标注")
    parser.add_argument("--skill_capacity_models", default=None,
                        help="--suite skill_capacity 限定测试的目标模型简写，逗号分隔（qwen3-8b/qwen2.5_omini），"
                             "留空则两个目标模型都测（各自缺失时精确跳过，不影响另一个）")
    parser.add_argument("--skill_capacity_max", type=int, default=64,
                        help="--suite skill_capacity 倍增探测+二分搜索的硬上限 N（默认 64）；"
                             "倍增到该上限仍全部通过时结果标 converged=False，需调大重测，不当真实前沿使用")
    parser.add_argument("--skill_capacity_repeat", type=int, default=3,
                        help="--suite skill_capacity 每个 N 重复试探取多数票的次数（默认 3）")
    parser.add_argument("--skill_capacity_mode", choices=("direct", "builder", "both"), default="direct",
                        help="--suite skill_capacity 驱动路径：direct=直连取证前沿搜索通道（唯一能测出前沿数字的通道）；"
                             "builder=真实 QAIModelBuilder 端到端确认通道（在直连已测出的前沿 N 上确认选对+答对，"
                             "需要 --builder_dir/--genie_root_path 具备，环境不具备时精确跳过）；"
                             "both=两者都跑（Builder 分支先跑并自管 Builder/服务生命周期）。默认 direct")
    parser.add_argument("--skill_capacity_arms", choices=("legacy", "optimized", "both"), default="legacy",
                        help="--suite skill_capacity 档位对照：legacy=改造前基线（临时改写 prompt_engineering.json 的 "
                             "fidelity.{cjk,ascii}_chars_per_token=4.0 + budget_partition.enabled=false，改前备份、"
                             "finally 还原）；optimized=Step2 改造后的默认档位（不写覆盖，直接用 C++ 侧新默认值）；"
                             "both=依次跑两档并在 data 里各自记录 frontier_skills，供报告算提升倍数")
    parser.add_argument("--suite", choices=("full", "model", "sampleapp", "multimodal", "gguf", "multi_model", "mnn", "qnn", "graceful_shutdown", "prompt_fidelity", "skill_capacity", "long_task_memory"),
                        default=None, help="选择要运行的测试套件（必传参数，不再有隐式默认值；如需完整回归请显式传入 full）")
    parser.add_argument("--long_task_memory_models", default=None,
                        help="--suite long_task_memory 限定测试的目标模型简写，逗号分隔（qwen3-8b/gguf-20b/mnn-20b），"
                             "留空则三个目标模型都测（各自缺失时精确跳过，不影响其他）")
    parser.add_argument("--long_task_memory_max", type=int, default=8,
                        help="--suite long_task_memory 倍增探测+二分搜索的硬上限 N（默认 8，真机 LLM 推理成本远高于 "
                             "skill_capacity 的纯提示词判定，默认值偏小以控制真机耗时；倍增到该上限仍全部通过时 "
                             "结果标 converged=False，需调大重测，不当真实前沿使用）")
    parser.add_argument("--long_task_memory_repeat", type=int, default=1,
                        help="--suite long_task_memory 每个 N 重复试探取多数票的次数（默认 1，每次试探即 2 轮真实 "
                             "推理，真机耗时下先用 1 验证方法论，充裕时再调大）")
    parser.add_argument("--long_task_memory_filler_lines", type=int, default=6,
                        help="--suite long_task_memory 每个填充轮工具输出的行数（默认 6，越大越快挤占预算触发丢弃）")
    parser.add_argument("--long_task_memory_timeout", type=int, default=180,
                        help="--suite long_task_memory 单次 HTTP 请求超时秒数（默认 180；真机推理为秒级到十几秒级，"
                             "不能套用纯单测的短超时，但仍需留有余量避免真正挂起拖死整个套件）")
    parser.add_argument("--long_task_memory_arms", choices=("legacy", "optimized", "both"), default="both",
                        help="--suite long_task_memory 档位对照：legacy=task_memo.enabled=false（当前默认纯数字 "
                             "占位）；optimized=task_memo.enabled=true（model_layer_enabled=false 保证判定确定性）；"
                             "both=依次跑两档并记录 frontier，供报告算提升倍数/差值（默认 both）")
    parser.add_argument("--long_task_memory_mode", choices=("direct", "client", "both"), default="direct",
                        help="--suite long_task_memory 驱动路径：direct=Python 直连读 X-Genie-Prompt-Memo-* 头做 "
                             "细粒度断言与二分搜索前沿（唯一能测出前沿数字的通道）；client=GenieAPIClient.exe "
                             "--raw_file 端到端交叉确认（只在 direct 已测出的前沿附近抽样，不独立求前沿）；"
                             "both=两者都跑。默认 direct")
    parser.add_argument("--long_task_memory_service_mode", choices=("stateless", "stateful", "both"), default="stateless",
                        help="--suite long_task_memory 服务模式：stateless=-n -1；stateful=常规 -n。"
                             "已更正的架构事实：压缩管线（含 TaskMemoBuilder）对这两种模式完全无分支、等价运行，"
                             "`-n` 只决定客户端断开后服务端是否额外持久化历史（和本套件断言无关），因此 stateful 也同样做 "
                             "legacy/optimized 双臂对照；both=两者都跑。默认 stateless")
    parser.add_argument("--long_task_memory_stateful_n", type=int, default=6,
                        help="--suite long_task_memory stateful 模式下传给服务的 -n 值（默认 6）")
    parser.add_argument("--long_task_memory_new_fields_models", default="qwen3-8b",
                        help="--suite long_task_memory 中 Task Memo 新增字段（goal anchor/分页目录/跨模式一致性，"
                             "场景 A-D）这组轻量确定性回归限定测试的目标模型简写，逗号分隔，默认仅 qwen3-8b（控制"
                             "真机推理成本；这组场景不求前沿数字，每个场景只需额外 1-4 轮真实推理）")
    parser.add_argument("--model_name", default=None, help="--suite model/mnn/qnn/sampleapp 时按名称筛选模型，逗号分隔，未指定则测试该套件下全部已发现模型")

    args = parser.parse_args()

    # --rounds 下限校验：传 0/负数时 range(1, args.rounds+1) 会退化为空区间，导致该模型段
    # "零测试、零痕迹"地跑完，不报错也不影响退出码——这是需要在入口处堵住的静默异常行为。
    if args.rounds < 1:
        print(f"ERROR: --rounds 必须 >= 1（当前传入: {args.rounds}）")
        sys.exit(1)

    # --multimodal_rounds 与 --rounds 校验规则一致：显式传入且 < 1 时直接退出，不静默退化为空区间。
    # 未显式传入（None）时回退为 --rounds，与解耦前的默认行为保持一致。
    if args.multimodal_rounds is not None and args.multimodal_rounds < 1:
        print(f"ERROR: --multimodal_rounds 必须 >= 1（当前传入: {args.multimodal_rounds}）")
        sys.exit(1)
    args.multimodal_rounds = args.multimodal_rounds if args.multimodal_rounds is not None else args.rounds

    # --suite 校验放在最前面（与 --rounds/--multimodal_rounds 一起）：
    # 必须显式选择要运行的套件，不再有隐式默认值；提前到模型发现/远程连接之前报错，
    # 避免用户在环境准备好之后才发现忘了传 --suite。
    if args.suite is None:
        print("ERROR: 必须显式传入 --suite（不再有隐式默认值）。"
              "如需运行完整回归，请显式传入 --suite full。"
              f"可选值: {', '.join(SUITE_HANDLERS.keys())}")
        sys.exit(1)

    # 把所有用户传入的相对路径在第一时间转成绝对路径,
    # 防止后续 ServiceManager 用 cwd=exe_dir 启动子进程时,
    # 子进程把相对路径解析到 exe_dir 下面去 (例如 Stable\models\xxx\config.json)。
    if args.exe_dir:
        args.exe_dir = str(Path(args.exe_dir).resolve())
    if args.models:
        args.models = str(Path(args.models).resolve())
    if args.out_dir:
        args.out_dir = str(Path(args.out_dir).resolve())
    if args.data_dir:
        args.data_dir = str(Path(args.data_dir).resolve())
    if args.builder_dir:
        args.builder_dir = str(Path(args.builder_dir).resolve())

    remote_mode = args.remote

    if remote_mode:
        # 远程模式：从服务获取模型列表
        print(f"远程模式：连接 {args.host}:{args.port}")
        models = discover_models_remote(args.host, args.port)
        if not models:
            print(f"ERROR: 无法从远程服务获取模型列表，请确认服务是否在运行")
            sys.exit(1)
    else:
        # 本地模式：验证输入
        if not args.exe_dir:
            print("ERROR: 本地模式需要 --exe_dir 参数（或使用 --remote 连接已运行的服务）")
            sys.exit(1)
        if not args.models:
            print("ERROR: 本地模式需要 --models 参数（或使用 --remote 连接已运行的服务）")
            sys.exit(1)

        exe_dir = Path(args.exe_dir)
        exe_path = exe_dir / "GenieAPIService.exe"
        if not exe_path.exists():
            print(f"ERROR: 找不到 {exe_path}")
            sys.exit(1)

        models_dir = Path(args.models)
        models = discover_models(models_dir)
        if not models:
            print(f"ERROR: models 目录中没有找到包含 config.json 的子目录: {models_dir}")
            sys.exit(1)

    out_dir = Path(args.out_dir)
    out_dir.mkdir(parents=True, exist_ok=True)

    # Builder 使用的 python.exe：优先显式 --builder_python，否则探测官方 Setup.bat 搭建的
    # 独立 venv，都找不到则回退 sys.executable 并打印警告（而非静默失败）。
    args.builder_python_exe = resolve_builder_python(args.builder_python)
    # Builder 隔离数据目录（QAI_DATA__DATA_DIR）：默认落在 <out_dir>/qaimodelbuilder_data，
    # 每次运行新建、非持久；显式传入时按用户指定路径解析为绝对路径（可用于复用/持久化）。
    args.builder_data_dir = (
        str(Path(args.builder_data_dir).resolve()) if args.builder_data_dir
        else str(out_dir / "qaimodelbuilder_data")
    )
    # 供 Builder 使用的 GenieAPIService 安装目录：未显式传入时复用 --exe_dir（本地模式下它
    # 已经就是包含 GenieAPIService.exe 的目录），远程模式下无 --exe_dir 时保持 None，由
    # 需要它的 suite（如 skill_capacity 的 builder 模式）内部自己精确报错并 skip。
    if args.genie_root_path:
        args.genie_root_path = str(Path(args.genie_root_path).resolve())
    elif args.exe_dir:
        args.genie_root_path = args.exe_dir

    print("=" * 60)
    print("GenieAPIService 集成测试")
    print("=" * 60)
    if remote_mode:
        print(f"  模式: 远程（连接已运行的服务）")
    else:
        print(f"  模式: 本地（自动启动/停止）")
        print(f"  Exe 目录: {args.exe_dir}")
        print(f"  模型目录: {args.models}")
    print(f"  发现模型: {models}")
    print(f"  测试轮数: {args.rounds}")
    print(f"  多模态测试轮数: {args.multimodal_rounds}")
    print(f"  服务地址: {args.host}:{args.port}")
    print(f"  输出目录: {out_dir}")
    print(f"  性能采集: {'启用' if HAS_PSUTIL else '禁用 (psutil 未安装)'}")
    print("=" * 60)

    # --suite 是否合法/是否显式传入，已在 main() 顶部与其它参数校验一起提前检查过，
    # 到这里 args.suite 必然非 None。
    effective_suite = args.suite

    handler = SUITE_HANDLERS[effective_suite]

    # 不支持 --model_name 的 suite（multimodal/multi_model：分别用自动筛选/全量并发逻辑，
    # 不读取该参数）若检测到用户显式传入该参数，打印一条不阻断执行的提示，避免参数被
    # 静默忽略、用户却毫无察觉。
    _SUITES_WITHOUT_MODEL_NAME = {"multimodal", "multi_model"}
    if args.model_name and effective_suite in _SUITES_WITHOUT_MODEL_NAME:
        print(f"提示: --suite {effective_suite} 不支持 --model_name 过滤，该参数将被忽略"
              f"（当前传入: {args.model_name}）")

    all_results, all_perf_samples, all_crash_events = handler(args, models, remote_mode, out_dir)

    # 本次运行调用 test_service.py 时的完整命令行（含全部参数），一路传给 _finalize_and_exit
    # 再转给 generate_summary_html/generate_model_reports，在报告 header 里展示，
    # 便于事后复核"这次跑的到底是什么命令"。
    cmdline = shlex.join(sys.argv)

    _finalize_and_exit(all_results, all_perf_samples, all_crash_events, out_dir, remote_mode, effective_suite, cmdline=cmdline)


if __name__ == "__main__":
    main()
