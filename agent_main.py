#!/usr/bin/env python3
"""
Universal-Game-Framework 主程序 agent_main.py
=====================================
MCP Client 主循环，串联全部模块：

  感知(perceive_game) → 预判(predict_all_entities) → 战斗评估(combat_judge)
  → LLM 决策 → 执行(game_action，带移动抖动) → 循环

附加功能：
- 死亡防抖：连续 N 帧 alive=false 才判定真实死亡（N = agent.death_frame_threshold，默认 8）
- 复盘过滤：只有 highest_boss / boss / 组队对局才生成复盘 md
- 统一复盘模板（v0.2）：结果 / 面对怪物 / 自身套装 / 死亡原因 / 可改进点
- 崩溃兜底清理（v0.2）：启动时清理上次残留的临时帧目录与截图
- BOSS 习惯记忆：每 12 秒批量追加写入 knowledge_md
- 鼠标角落安全暂停：鼠标碰到屏幕四角自动暂停
- 滚动日志：run_logs/ 最大 500KB 自动截断
- 随机抖动：移动坐标加固定小范围偏移，模拟真人
- highest_boss 动态避险：实力强可周旋，弱全力逃跑
- 组队协同：读取队友花瓣套装，调整我方推荐套装
- 实力评估防抖（v0.2）：CombatEvaluator 每 0.7s 重算一次

v0.3 基础战术扩充：
- 多套装自动切换：按战斗评估结果调用 switch_set，实际切换
- 战术记忆：每次换套写入 player_tactics.md（什么情况用什么套）
- BOSS 习性记忆增强：不只记坐标，归纳移动模式/追踪距离/攻击接近
- 简单组队协同：识别队友 → 分工 → 保持距离跟随
- 安全区检测：走位目标钳制在安全区内，防贴墙卡死
- 随机停顿：偶发 100~300ms 停顿 + 移动路径微扰（拟人）
"""
import argparse
import asyncio
import json
import math
import os
import random
import shutil
import sys
import time
from datetime import datetime

import requests
import gzip
from dotenv import load_dotenv

import config

load_dotenv()

# ---------------------------------------------------------------------------
# 配置（v0.5：全部来自 config.yaml，改参数不用改源码；热加载见 reload_config）
# ---------------------------------------------------------------------------
LLM_API_URL = os.getenv("LLM_API_URL", "")
LLM_API_KEY = os.getenv("LLM_API_KEY", "")
LLM_MODEL = os.getenv("LLM_MODEL", "")

BASE_DIR = os.path.dirname(os.path.abspath(__file__))
MCP_SERVER_SCRIPT = os.path.join(BASE_DIR, "mcp_server.py")


def _env_flag(name: str, default: bool = False) -> bool:
    raw = os.getenv(name)
    if raw is None:
        return default
    return raw.strip().lower() in ("1", "true", "yes", "on")


# v2.0 S7：UGF_DRY_RUN=1 —— 不碰真实键鼠、不调外部 LLM、不要求感知服务常驻，
# 只走 detect→brief→research→ensure→play→report 全流程并写状态/日志。
DRY_RUN = _env_flag("UGF_DRY_RUN")


def _mcp_server_env() -> dict:
    """
    MCP stdio 客户端只向子进程透传白名单变量（实测：ugf_* 之类一律丢失），
    dry-run / 感知后端等开关必须显式带上，否则"父进程开了开关、子进程没收到"。
    """
    try:
        from mcp.client.stdio import get_default_environment
        env = dict(get_default_environment())
    except Exception:
        env = {k: os.environ[k] for k in
               ("PATH", "HOME", "SHELL", "TERM", "USER", "LOGNAME") if k in os.environ}
    for key, val in os.environ.items():
        if key.startswith("UGF_"):
            env[key] = val
    if DRY_RUN:
        env["UGF_DRY_RUN"] = "1"
    # v2.0 S15：游戏选择变量也必须透传。此前只转发 UGF_*，AGENT_GAME 在 stdio 子进程里
    # 丢失 —— 父进程按 space_invaders 决策、MCP 子进程却加载 florr 档案（实体/套装/端口
    # 全是错的），且退出码仍为 0，属于跨进程静默不一致。
    # 直接以父进程**已解析**的结果写入，保证父子口径绝对一致，而不依赖透传是否成功。
    env["AGENT_GAME"] = config.active_game()
    env["UGF_GAME"] = env["AGENT_GAME"]
    return env


def _kb_game() -> str:
    """
    知识库的游戏分区名（v2.0 S15）。

    此前所有 kb_write / kb_append 都不带 game_name，写进 knowledge_md/ 根目录 ——
    多游戏共用一份知识库，第二款游戏的复盘与 BOSS 记忆会串到第一款里，
    且 `kb_search` 检索到的是别的游戏的经验。改用激活游戏名做分区。
    """
    return config.active_game()


def _late_report(round_count, total_deaths):
    """v1.7 局中进度汇报：写单文件 + 可选 Webhook，在后台线程跑，不阻塞主循环。"""
    import report_notifier
    game = config.active_game()

    def _run():
        actions = report_notifier.notify_progress(round_count, total_deaths, game)
        log(f"[汇报] 局中进度(回合 {round_count}, 死亡 {total_deaths}): "
            + " | ".join(actions))

    try:
        import threading
        threading.Thread(target=_run, daemon=True).start()
    except Exception as e:
        log(f"[汇报] 局中进度上报启动失败: {e}")


def _tool_text(result) -> str:
    """MCP CallToolResult → 纯文本；不同 SDK 版本返回形状不同，统一兜底。"""
    try:
        content = result.content
    except Exception:
        content = None
    if content is None:          # 非 CallToolResult 形状（字符串 / 自定义对象）
        try:
            return str(result) if result is not None else ""
        except Exception:
            return ""
    if not content:              # 空 content：明确返回空串，不要退化成对象 repr
        return ""
    try:
        return content[0].text
    except Exception:
        return ""


def _tool_error(result) -> str:
    """
    MCP 工具调用"软失败"检测（v2.0 S7）：
    call_tool 对未知工具/内部异常并不抛异常，而是把错误塞进返回内容；
    不检查就会出现"日志说已写入、实际什么都没写"的静默失败（kb_append 即实测案例）。
    """
    text = _tool_text(result)
    low = text.lower()
    for key in ("unknown tool", "failed", "traceback", "错误"):
        if key in low:
            return text
    return ""


def _json_fields(text: str, *keys) -> str:
    """从 JSON 文本里取若干字段拼成可读片段；取不到就给空串（不影响主循环）。"""
    try:
        data = json.loads(text)
    except Exception:
        return ""
    if not isinstance(data, dict):
        return ""
    parts = [f"{k}={data[k]}" for k in keys if data.get(k) not in (None, "")]
    return "，".join(parts)


def reload_config():
    """从 config.yaml 重读参数（热加载入口）。"""
    global LOG_DIR, DEATH_FRAME_THRESHOLD, BOSS_MEMORY_INTERVAL
    global LOG_MAX_SIZE, CORNER_MARGIN
    global BOSS_SAMPLE_MAX, BOSS_CLOSE_DIST, LEARNING_STATS_INTERVAL
    global REPORT_EVERY

    LOG_DIR = os.path.join(BASE_DIR, config.get("paths.run_logs", "run_logs"))
    DEATH_FRAME_THRESHOLD = config.get("agent.death_frame_threshold", 2)
    BOSS_MEMORY_INTERVAL = config.get("agent.boss_memory_interval", 12)
    LOG_MAX_SIZE = config.get("logs.max_size_mb", 20) * 1024 * 1024
    CORNER_MARGIN = config.get("combat.safe_zone_margin", 100)  # 复用安全区边距
    BOSS_SAMPLE_MAX = config.get("agent.boss_sample_max", 120)
    BOSS_CLOSE_DIST = config.get("agent.boss_close_dist", 120)
    LEARNING_STATS_INTERVAL = _int_env(
        "UGF_LEARN_EVERY", config.get("agent.learning_stats_interval", 24))
    # v1.7 局中定时汇报间隔(轮)，0=关闭；环境变量用于 dry-run 中验证心跳而不改 config.yaml
    REPORT_EVERY = _int_env("UGF_REPORT_EVERY", config.get("agent.report_every", 0))


def _int_env(name: str, default) -> int:
    """读整型环境变量，缺失/非法时回退到配置值（不抛异常，避免脏 env 炸主循环）。"""
    raw = os.getenv(name)
    if raw is None or str(raw).strip() == "":
        try:
            return int(default or 0)
        except (TypeError, ValueError):
            return 0
    try:
        return int(str(raw).strip())
    except ValueError:
        try:
            return int(default or 0)
        except (TypeError, ValueError):
            return 0


reload_config()
os.makedirs(LOG_DIR, exist_ok=True)

try:
    from mcp import ClientSession, StdioServerParameters
    from mcp.client.stdio import stdio_client
except ImportError:
    print("错误: 请先安装 mcp: pip install mcp")
    sys.exit(1)

# 本地模块
import combat_judge

SERVER_PARAMS = StdioServerParameters(command=sys.executable,
                                      args=[MCP_SERVER_SCRIPT],
                                      env=_mcp_server_env(),
                                      cwd=BASE_DIR)


# ---------------------------------------------------------------------------
# 滚动日志（v0.5：按天滚动 + 超限压缩 + 超期清理）
# ---------------------------------------------------------------------------
def _log_cleanup(days: int = None):
    """删除超过保留天数的旧日志（.log / .gz），硬盘占用有上限。"""
    days = days or config.get("logs.retention_days", 7)
    cutoff = time.time() - days * 86400
    try:
        for fn in os.listdir(LOG_DIR):
            fp = os.path.join(LOG_DIR, fn)
            if os.path.isfile(fp) and fn.startswith("agent_") and os.path.getmtime(fp) < cutoff:
                os.remove(fp)
    except OSError:
        pass


def _maybe_rotate():
    """当日日志超过大小上限 → 压缩为 .gz 并另起新文件。"""
    today = datetime.now().strftime("%Y%m%d")
    daily = os.path.join(LOG_DIR, f"agent_{today}.log")
    if os.path.exists(daily) and os.path.getsize(daily) > LOG_MAX_SIZE:
        gz = f"{daily}.{int(time.time())}.gz"
        with open(daily, "rb") as fi, gzip.open(gz, "wb") as fo:
            shutil.copyfileobj(fi, fo)
        os.remove(daily)


def log(msg: str):
    """写当日日志并打印；超限自动压缩，保留期外自动删除。"""
    daily = os.path.join(LOG_DIR, f"agent_{datetime.now().strftime('%Y%m%d')}.log")
    line = f"[{datetime.now().strftime('%H:%M:%S')}] {msg}\n"
    try:
        _log_cleanup()
        _maybe_rotate()
        with open(daily, "a", encoding="utf-8") as f:
            f.write(line)
    except Exception:
        pass
    print(line.rstrip())


# ---------------------------------------------------------------------------
# 崩溃兜底清理（v0.2）
# ---------------------------------------------------------------------------
def startup_cleanup():
    """
    启动时清理上次可能残留的临时文件：
    - video_frames/ 临时帧目录
    - /tmp/florr_frame.png 临时截图
    """
    frame_dir = os.path.join(BASE_DIR, "video_frames")
    if os.path.isdir(frame_dir):
        try:
            shutil.rmtree(frame_dir, ignore_errors=True)
            log(f"[清理] 已删除残留临时帧目录 {frame_dir}")
        except Exception as e:
            log(f"[清理] 删除临时帧目录失败: {e}")

    tmp_shot = "/tmp/florr_frame.png"
    if os.path.exists(tmp_shot):
        try:
            os.remove(tmp_shot)
            log("[清理] 已删除残留临时截图 /tmp/florr_frame.png")
        except OSError:
            pass

    # v1.0 知识库体积维护：归档超限旧笔记 + 合并重复笔记
    try:
        import kb_maintainer
        log(kb_maintainer.run())
    except Exception as e:
        log(f"[清理] 知识库维护失败: {e}")


# ---------------------------------------------------------------------------
# LLM 决策
# ---------------------------------------------------------------------------
SYSTEM_PROMPT = """你是 Universal-Game-Framework，一个玩 florr.io 的游戏智能体，目标是优先保命、持续作战。
可调用工具：perceive_game, kb_search, predict_all_entities, game_action, kb_write, handle_afk, reset_predictor。
套装切换(switch_set)由战斗评估自动执行，无需你手动调用。
决策规则：
- afk_popup=true 优先处理验证
- 遇 highest_boss(Unique/Eternal) 时，根据自身实力评估：实力不足全力避险，实力充足可谨慎周旋
- 预判置信度<0.6 时，降低对预判坐标的依赖，更多参考当前画面
- 有队友时注意保持安全距离，配合分工
- 每步只输出一个动作 JSON：{"action":"move","x":100,"y":200}
动作：move(x,y) / attack / defend / synthesize / idle。"""


def llm_decide(game_state: str, predictions: str, combat_eval: str,
               kb_tactics: str) -> dict:
    """调用 LLM 决策，无 API 时走兜底逻辑。"""
    if not LLM_API_URL or not LLM_API_KEY:
        return _fallback_decide(game_state, combat_eval)

    headers = {"Authorization": f"Bearer {LLM_API_KEY}",
               "Content-Type": "application/json"}
    user_content = (
        f"当前游戏状态:\n{game_state}\n\n"
        f"实体预判(未来1.2秒):\n{predictions}\n\n"
        f"战斗评估:\n{combat_eval}\n\n"
        f"知识库战术:\n{kb_tactics}\n\n"
        "请输出下一步动作的 JSON。"
    )
    payload = {
        "model": LLM_MODEL,
        "messages": [
            {"role": "system", "content": SYSTEM_PROMPT},
            {"role": "user", "content": user_content},
        ],
        "max_tokens": 150,
        "temperature": 0.3,
    }
    try:
        resp = requests.post(LLM_API_URL, headers=headers, json=payload, timeout=15)
        resp.raise_for_status()
        content = resp.json()["choices"][0]["message"]["content"].strip()
        if "```" in content:
            content = content.split("```")[1]
            if content.startswith("json"):
                content = content[4:]
        return json.loads(content)
    except Exception as e:
        log(f"[LLM] 决策失败，使用兜底: {e}")
        return _fallback_decide(game_state, combat_eval)


def _fallback_decide(game_state_str: str, combat_eval_str: str) -> dict:
    """无 LLM 时的兜底决策。"""
    try:
        state = json.loads(game_state_str)
    except Exception:
        return {"action": "idle"}
    try:
        ev = json.loads(combat_eval_str)
    except Exception:
        ev = {}

    if state.get("afk_popup"):
        return {"action": "idle"}

    decision = ev.get("decision", "fight")
    if decision == "retreat":
        # 跑路：往远离最高威胁的方向移动
        return {"action": "defend"}
    if decision == "cautious_fight":
        return {"action": "attack"}
    return {"action": "attack"}


# ---------------------------------------------------------------------------
# 复盘与记忆
# ---------------------------------------------------------------------------
def _should_review(state_data: dict, has_teammate: bool) -> bool:
    """复盘过滤：只有 highest_boss / boss / 组队对局才生成复盘。"""
    entities = state_data.get("entities", [])
    has_boss = any(e.get("category") in ("highest_boss", "boss") for e in entities)
    # 注意：perceive 返回的 entities 还没经过 predictor 分类，
    # 这里用 rarity 粗判
    has_boss = has_boss or any(
        e.get("rarity", "").capitalize() in ("Super", "Unique", "Eternal")
        for e in entities
    )
    return has_boss or has_teammate


async def review_round(session, survived: bool, note: str, state: str):
    """对局复盘，按统一模板写入知识库 md（v0.2）。"""
    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    outcome = "存活" if survived else "死亡"

    # 从最终画面状态尽力提取字段
    monster_info, set_info, cause = "未知", "未知", note
    try:
        s = json.loads(state)
        p = s.get("player", {})
        set_info = p.get("petal_set", "未知")
        ents = s.get("entities", [])
        if ents:
            monster_info = "、".join(
                f"{e.get('raw_id','?')}({e.get('rarity','?')})" for e in ents[:5]
            )
        if not survived:
            cause = f"死亡。当时面对怪物: {monster_info}，自身套装: {set_info}"
    except Exception:
        pass

    content = (
        f"# 对局复盘 — {timestamp}\n\n"
        f"- 结果: {outcome}\n"
        f"- 面对怪物: {monster_info}\n"
        f"- 自身套装: {set_info}\n"
        f"- 死亡原因: {cause}\n"
        f"- 可改进点: {note}\n"
    )

    # v0.4 复盘升级：先检索历史相似对局（同怪物），附上对比，帮助找出改进点
    try:
        history = await session.call_tool("kb_search", {"keyword": "对局复盘",
                                              "game_name": _kb_game()})
        text = history if isinstance(history, str) else str(history)
        # 粗略提取出历史有效战绩的结论
        content += "\n## 与历史对局对比\n"
        if monster_info != "未知" and monster_info in text:
            content += f"- 历史上出现过同类怪物({monster_info})的复盘，可重点回顾上次的决策差异\n"
        else:
            content += "- 暂无同怪物历史复盘\n"
    except Exception:
        content += "\n- 历史对比检索失败\n"

    res = await session.call_tool("kb_write", {
        "filename": f"review_{timestamp}",
        "markdown_content": content,
        "game_name": _kb_game(),
    })
    await session.call_tool("reset_predictor")
    err = _tool_error(res)
    log(f"[复盘] 对局结束，结果={outcome}"
        + ("，经验已写入知识库" if not err else f"，写知识库失败: {err[:150]}")
        + "，预判历史已清空")


# ---------------------------------------------------------------------------
# BOSS 习惯记忆（v0.3 增强：归纳行为模式）
# 相关阈值（BOSS_SAMPLE_MAX / BOSS_CLOSE_DIST）由 reload_config 从 config.yaml 读取
# ---------------------------------------------------------------------------


def _analyze_boss_behavior(samples: list) -> str:
    """
    从坐标样本归纳 BOSS 行为模式。
    samples: [(ex, ey, px, py), ...]（BOSS 位置 + 玩家位置）
    返回一句话：移动模式 + 追踪距离 + 攻击接近倾向。
    """
    n = len(samples)
    if n < 3:
        return "样本不足，暂无法归纳"
    # 移动模式：平均每次转角大小决定 绕圈/直线/徘徊
    turns = []
    for i in range(1, n - 1):
        ax = samples[i][0] - samples[i - 1][0]
        ay = samples[i][1] - samples[i - 1][1]
        bx = samples[i + 1][0] - samples[i][0]
        by = samples[i + 1][1] - samples[i][1]
        da = (ax * ax + ay * ay) ** 0.5
        db = (bx * bx + by * by) ** 0.5
        if da < 1 or db < 1:
            continue
        cos_t = max(-1.0, min(1.0, (ax * bx + ay * by) / (da * db)))
        turns.append(math.degrees(math.acos(cos_t)))
    avg_turn = sum(turns) / len(turns) if turns else 0.0
    if avg_turn > 30:
        pattern = "绕圈/游走"
    elif avg_turn < 15:
        pattern = "直线移动"
    else:
        pattern = "缓行徘徊"

    dists = [((px - ex) ** 2 + (py - ey) ** 2) ** 0.5
             for ex, ey, px, py in samples]
    avg_dist = sum(dists) / len(dists)
    close_cnt = sum(1 for d in dists if d < BOSS_CLOSE_DIST)
    return (f"{pattern}；平均距离玩家约 {avg_dist:.0f}px；"
            f"近距离接近 {close_cnt} 次（越接近越凶/仇恨越强）")


async def write_boss_memory(session, boss_observations: list, boss_samples: dict = None):
    """每 12 秒批量写入 BOSS 行为习惯记忆（轨迹 + 行为归纳）。"""
    if not boss_observations:
        return
    timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
    content = f"# BOSS 行为观察 — {timestamp}\n\n"
    for obs in boss_observations:
        content += f"- {obs}\n"
    # v0.3：多次遭遇累计的行为共性归纳
    if boss_samples:
        content += "\n## 行为归纳（多次遭遇累计共性）\n"
        for uid, samples in boss_samples.items():
            if len(samples) >= 3:
                content += f"- {uid}: {_analyze_boss_behavior(samples)}\n"
    res = await session.call_tool("kb_append", {
        "filename": "boss_behavior_log",
        "markdown_content": content,
        "game_name": _kb_game(),
    })
    err = _tool_error(res)
    if err:
        log(f"[记忆] BOSS 行为记忆写入失败: {err[:200]}")
    else:
        log(f"[记忆] 已写入 {len(boss_observations)} 条 BOSS 行为观察")


# ---------------------------------------------------------------------------
# 鼠标角落安全检查
# ---------------------------------------------------------------------------
def _is_mouse_in_corner(screen_w: int = 1920, screen_h: int = 1080) -> bool:
    """检查鼠标是否在屏幕四角（安全暂停触发）。"""
    try:
        import pyautogui
        x, y = pyautogui.position()
        return (x < CORNER_MARGIN or x > screen_w - CORNER_MARGIN or
                y < CORNER_MARGIN or y > screen_h - CORNER_MARGIN)
    except Exception:
        return False


# v1.1 监控大盘快照：每 N 回合把关键状态写到 run_logs/agent_snapshot.json
SNAPSHOT_EVERY = 2
_snap_last_round = [0]  # 记录上一次写入的回合，避免重复写


def write_snapshot(round_count, total_deaths, player, predictions, combat_eval, game):
    """轻量快照，供 admin_panel(监控大盘)读取；令牌昂贵字段只存摘要。"""
    try:
        import json as _json
        snap_dir = os.path.join(BASE_DIR, config.get("paths.run_logs", "run_logs"))
        os.makedirs(snap_dir, exist_ok=True)
        # 只保留前若干条威胁摘要，避免快照过大
        threats = []
        try:
            import json as _j  # noqa
            pred = _j.loads(predictions) if isinstance(predictions, str) and predictions.startswith("[") else []
            for t in pred[:6]:
                # v2.0 S7：predictor 输出的是 x_now/y_now + raw_id，
                # 原先按 x/y/name 取恒为 0 与空串，监控大盘上看不到威胁在哪
                threats.append({
                    "cat": t.get("category", "?"),
                    "name": t.get("raw_id") or t.get("name", ""),
                    "threat": t.get("threat_score", 0),
                    "x": t.get("x", t.get("x_now", 0)),
                    "y": t.get("y", t.get("y_now", 0)),
                })
        except Exception:
            threats = []
        data = {
            "time": datetime.now().strftime("%Y-%m-%d %H:%M:%S"),
            "round": round_count, "deaths": total_deaths,
            "hp": player.get("hp"), "max_hp": player.get("max_hp"),
            "decision": combat_eval.get("decision"), "mindset": combat_eval.get("mindset"),
            "set": combat_eval.get("recommended_set"), "game": game,
            "threats": threats,
        }
        with open(os.path.join(snap_dir, "agent_snapshot.json"), "w", encoding="utf-8") as f:
            _json.dump(data, f, ensure_ascii=False)
        _snap_last_round[0] = round_count
    except Exception:
        pass


# ---------------------------------------------------------------------------
# 主循环
# ---------------------------------------------------------------------------
async def run_agent(interval: float = 0.5, max_rounds: int = 0):
    log("=" * 55)
    log("  Universal-Game-Framework 启动 (MCP Client + 预判 + 战斗评估)")
    if DRY_RUN:
        log("  模式: DRY-RUN —— 无真实键鼠 / 无外部 LLM / 感知走进程内 mock")
    log("=" * 55)

    # v0.2 崩溃兜底：启动时清理残留临时文件
    startup_cleanup()

    async with stdio_client(SERVER_PARAMS) as (read, write):
        async with ClientSession(read, write) as session:
            await session.initialize()
            tools = await session.list_tools()
            log(f"[MCP] 已连接，可用工具: {[t.name for t in tools.tools]}")

            kb_result = await session.call_tool("kb_list")
            log(f"[知识库] 当前文档: {_tool_text(kb_result)[:150]}")

            # 运行状态
            round_count = 0
            total_deaths = 0          # v1.1 累计死亡数（供监控大盘）
            game_state = "{}"
            death_streak = 0          # 连续死亡帧数
            skipped_frames = 0        # v2.0 S7 感知跳过帧数（dry-run 验收用）
            action_counts = {}        # v2.0 S7 动作分布（dry-run 验收用）
            set_switches = 0          # v2.0 S7 换套次数
            last_boss_memory_time = 0
            boss_observations = []
            boss_samples = {}         # v0.3：BOSS 坐标样本，累积归纳习性
            current_set = "combat"    # 当前套装，用于换套去抖
            learn_stats = []          # v0.4 学习命中统计：[("战术", True/False), ...]
            death_count_this_cycle = 0  # v1.0 本统计周期内死亡数（喂给自动调参）
            paused = False
            evaluator = combat_judge.CombatEvaluator()  # v0.2 评估防抖

            log("\n[Agent] 进入游戏主循环...\n")

            try:
                while True:
                    # v2.0 S7：先判定再自增，保证 round_count 等于"实际执行回合数"
                    # （原先自增后判定，日志会多报 1 轮）
                    if max_rounds and round_count >= max_rounds:
                        log("[Agent] 达到最大轮数，退出")
                        break
                    round_count += 1

                    # v0.5 热加载：config.yaml 变了就刷新各模块常量
                    if config.reload_if_changed():
                        reload_config()
                        combat_judge.reload_config()
                        # predictor 运行在 MCP 子进程，由其 predict 入口自行热加载
                        log("[配置] config.yaml 已变更，热加载完成")

                    # 鼠标角落安全暂停
                    if _is_mouse_in_corner():
                        if not paused:
                            log("[安全] 鼠标在屏幕角落，暂停 Agent")
                            paused = True
                        await asyncio.sleep(1)
                        continue
                    if paused:
                        log("[安全] 鼠标离开角落，恢复 Agent")
                        paused = False

                    # 1. 感知
                    perceive_result = await session.call_tool("perceive_game")
                    game_state = _tool_text(perceive_result) or "{}"

                    # v2.0 S7：把 _reason / _error 打出来，否则"跳过本帧"看不到具体原因
                    if '"_skipped"' in game_state:
                        log(f"[感知] 跳过本帧（{_json_fields(game_state, '_reason', '_error')}）")
                        skipped_frames += 1
                        await asyncio.sleep(interval)
                        continue
                    if '"error"' in game_state:
                        log(f"[感知] 异常: {_json_fields(game_state, 'error', 'message')}"
                            f" {game_state[:80]}")
                        await asyncio.sleep(2)
                        continue

                    state_data = json.loads(game_state)
                    player = state_data.get("player", {})

                    # 2. 死亡防抖检测
                    if not player.get("alive", True):
                        death_streak += 1
                        if death_streak >= DEATH_FRAME_THRESHOLD:
                            death_count_this_cycle += 1  # v1.0 计入死亡
                            total_deaths += 1            # v1.1 累计死亡
                            # 判定真实死亡，复盘（过滤普通小怪局）
                            has_teammate = bool(state_data.get("teammates", []))
                            if _should_review(state_data, has_teammate):
                                await review_round(session, False,
                                                   "玩家死亡，复盘本局",
                                                   game_state)
                            else:
                                log("[复盘] 普通小怪局，不生成复盘 md（节省硬盘）")
                                await session.call_tool("reset_predictor")
                            death_streak = 0
                            evaluator.invalidate()  # 死亡后强制重算
                            await asyncio.sleep(2)
                            continue
                    else:
                        death_streak = 0

                    # 3. 预判
                    pred_result = await session.call_tool("predict_all_entities")
                    predictions = _tool_text(pred_result) or "[]"

                    # 4. 战斗评估（v0.2 防抖：0.7s 内命中缓存不重算）
                    pred_data = json.loads(predictions) if predictions.startswith("[") else []
                    # v0.3 组队识别：perceive 已返回队友列表
                    teammates = [
                        combat_judge.Teammate(
                            raw_id=t.get("raw_id", "ally"),
                            petal_set=t.get("petal_set", "combat"),
                            x=t.get("x", 0),
                            y=t.get("y", 0),
                        )
                        for t in state_data.get("teammates", [])
                    ]
                    ctx = combat_judge.CombatContext(
                        player=combat_judge.PlayerState(
                            hp=player.get("hp", 100),
                            max_hp=player.get("max_hp", 100),
                            power_score=player.get("power_score", 100),
                            current_set=current_set,
                            talent=player.get("talent", "none"),
                            x=player.get("x", 0),
                            y=player.get("y", 0),
                        ),
                        enemies=pred_data if isinstance(pred_data, list) else [],
                        teammates=teammates,
                    )
                    combat_eval = evaluator.evaluate(ctx)
                    combat_eval_str = json.dumps(combat_eval, ensure_ascii=False)

                    # v1.1 监控快照：每 N 回合写一次 run_logs/agent_snapshot.json
                    if round_count - _snap_last_round[0] >= SNAPSHOT_EVERY:
                        write_snapshot(round_count, total_deaths, player,
                                       predictions, combat_eval,
                                       config.active_game())

                    # v1.7 局中定时汇报：每 REPORT_EVERY 轮上报一次进度（0=关闭）
                    if REPORT_EVERY and round_count % REPORT_EVERY == 0:
                        try:
                            _late_report(round_count, total_deaths)
                        except Exception as e:  # 汇报失败绝不影响主循环
                            log(f"[汇报] 局中进度上报失败: {e}")

                    # 5. 套装自动切换 + 战术记忆（v0.3）
                    recommended_set = combat_eval.get("recommended_set")
                    if recommended_set and recommended_set != current_set:
                        await session.call_tool("switch_set", {"set_name": recommended_set})
                        _res = await session.call_tool("kb_append", {
                            "filename": "player_tactics",
                            "markdown_content": (
                                f"- {datetime.now().strftime('%Y-%m-%d %H:%M:%S')} "
                                f"决策={combat_eval.get('decision')} "
                                f"心态={combat_eval.get('mindset')} "
                                f"威胁比={combat_eval.get('threat_ratio')} "
                                f"→ 换 {recommended_set} 套"
                            ),
                        })
                        _err = _tool_error(_res)
                        if _err:
                            log(f"[战术] 写入 player_tactics 失败: {_err[:150]}")
                        log(f"[套装] {current_set} → {recommended_set}，已记入 player_tactics.md")
                        current_set = recommended_set
                        set_switches += 1

                    # 6. 检索知识库
                    keyword = "boss" if combat_eval.get("has_highest_boss") else "战术"
                    kb_result = await session.call_tool("kb_search", {"keyword": keyword})
                    try:
                        kb_tactics = kb_result.content[0].text
                    except Exception:
                        kb_tactics = str(kb_result)
                    # v0.4 学习效果验证：记录每次决策是否命中知识库
                    # 命中 = 检索结果非空 且不包含"未找到"类提示
                    low = (kb_tactics or "").lower()
                    hit = bool(kb_tactics) and not any(
                        k in low for k in ("未找到", "没有找到", "无相关")
                    )
                    learn_stats.append((keyword, hit))

                    # 7. LLM 决策
                    action = llm_decide(game_state, predictions, combat_eval_str, kb_tactics)
                    if not action:
                        action = {"action": "idle"}

                    # 8. 移动抖动 + 安全区钳制（v0.3 防贴墙卡死）
                    action_type = action.get("action", "idle")
                    action_args = {"action_type": action_type}
                    if action_type == "move":
                        tx = action.get("x", 400)
                        ty = action.get("y", 300)
                        tx, ty = combat_judge.clamp_to_safe_zone(tx, ty)
                        tx, ty = combat_judge.apply_jitter(tx, ty)
                        action_args["x"] = int(tx)
                        action_args["y"] = int(ty)

                    # 9. 执行（dry-run 下由 MCP 服务端记录动作但不碰键鼠）
                    exec_result = await session.call_tool("game_action", action_args)
                    action_counts[action_type] = action_counts.get(action_type, 0) + 1
                    exec_text = _tool_text(exec_result)
                    if any(k in exec_text for k in ("错误", "必须提供", "未知动作")):
                        log(f"[动作] 执行异常: {exec_text[:120]}")

                    # 10. BOSS 行为观察收集（v0.3 累积坐标样本，归纳习性）
                    if combat_eval.get("has_highest_boss") or any(
                        e.get("category") == "boss" for e in pred_data
                    ):
                        px, py = player.get("x", 0), player.get("y", 0)
                        for e in pred_data:
                            if e.get("category") not in ("boss", "highest_boss"):
                                continue
                            uid = f"{e.get('raw_id','?')}({e.get('rarity','?')})"
                            obs = (f"{datetime.now().strftime('%H:%M:%S')} "
                                   f"{uid} 位置({e.get('x_now')},{e.get('y_now')}) "
                                   f"预判({e.get('x_predict')},{e.get('y_predict')}) "
                                   f"决策={combat_eval.get('decision')}")
                            boss_observations.append(obs)
                            # 累积坐标样本（用于行为归纳），限制数量防内存膨胀
                            samples = boss_samples.setdefault(uid, [])
                            if len(samples) >= BOSS_SAMPLE_MAX:
                                samples.pop(0)
                            samples.append((e.get("x_now", 0), e.get("y_now", 0),
                                            px, py))

                    now = time.time()
                    if now - last_boss_memory_time > BOSS_MEMORY_INTERVAL:
                        await write_boss_memory(session, boss_observations, boss_samples)
                        boss_observations = []
                        last_boss_memory_time = now

                    # 偶发 100~300ms 停顿，模拟人类反应（v0.3）
                    if random.random() < 0.05:
                        await asyncio.sleep(random.uniform(0.1, 0.3))

                    # v0.4 学习效果验证：定期汇总命中率，标记薄弱方向
                    if round_count and round_count % LEARNING_STATS_INTERVAL == 0 and learn_stats:
                        weak = {}
                        for k, h in learn_stats:
                            col = weak.setdefault(k, [0, 0])
                            col[0] += 1
                            col[1] += int(h)
                        summary = [f"- {k}: {col[1]}/{col[0]} 次命中" for k, col in weak.items()]
                        _res = await session.call_tool("kb_append", {
                            "filename": "learning_stats",
                            "game_name": _kb_game(),
                            "markdown_content": (
                                f"- {datetime.now().strftime('%Y-%m-%d %H:%M:%S')} "
                                f"汇总：{'；'.join(summary)}。"
                                f"命中率低的方向({[k for k, c in weak.items() if c[1] == 0]})"
                                f"应优先补充教程"
                            ),
                        })
                        _err = _tool_error(_res)
                        if _err:
                            log(f"[学习] 命中率汇总写入失败: {_err[:150]}")
                        learn_stats = []
                        # v1.0 基础自动调参：按命中率 + 本周期死亡数微调阈值
                        try:
                            import auto_tuner
                            hits = sum(col[1] for col in weak.values())
                            attempts = sum(col[0] for col in weak.values())
                            log(auto_tuner.tune(hits=hits, attempts=attempts,
                                                deaths_extra=death_count_this_cycle))
                        except Exception as e:
                            log(f"[调参] 自动调参失败: {e}")
                        death_count_this_cycle = 0

                    # 日志
                    log(f"[回合 {round_count}] HP={player.get('hp')} "
                        f"敌人={len(pred_data) if isinstance(pred_data, list) else 0} "
                        f"队友={len(teammates)} "
                        f"决策={combat_eval.get('decision')} "
                        f"套装={current_set} "
                        f"心态={combat_eval.get('mindset')} "
                        f"→ {action_type}")

                    await asyncio.sleep(interval)

            except KeyboardInterrupt:
                log("\n[Agent] 收到中断信号")
            finally:
                # 退出前写剩余 BOSS 记忆；收尾失败绝不影响退出码
                try:
                    if boss_observations:
                        await write_boss_memory(session, boss_observations, boss_samples)
                except Exception as e:
                    log(f"[记忆] 退出前写 BOSS 记忆失败: {e}")
                try:
                    await review_round(session, True, "Agent 正常退出", game_state)
                except Exception as e:
                    log(f"[复盘] 退出前复盘失败（不影响退出）: {e}")
                log("[汇总] " + " | ".join([
                    f"回合={round_count}", f"死亡={total_deaths}",
                    f"跳过帧={skipped_frames}", f"换套={set_switches}",
                    "动作=" + (",".join(f"{k}x{v}" for k, v in sorted(action_counts.items()))
                               or "无"),
                ]))

    log("[Agent] 已断开 MCP 连接")


# ---------------------------------------------------------------------------
# 入口
# ---------------------------------------------------------------------------
def main():
    parser = argparse.ArgumentParser(description="Universal-Game-Framework 主程序")
    parser.add_argument("--interval", type=float, default=0.5,
                        help="决策循环间隔秒数，默认 0.5")
    parser.add_argument("--max-rounds", "--rounds", dest="max_rounds", type=int, default=0,
                        help="最大运行回合数，0=无限（--rounds 为等价别名）")
    args = parser.parse_args()

    if not os.path.exists(MCP_SERVER_SCRIPT):
        print(f"错误: 找不到 MCP 服务端 {MCP_SERVER_SCRIPT}")
        sys.exit(1)

    if DRY_RUN:
        print("[dry-run] 已开启：不做真实键鼠动作、不调用外部 LLM、"
              "感知缺失时走进程内 mock")
    try:
        asyncio.run(run_agent(interval=args.interval, max_rounds=args.max_rounds))
    except KeyboardInterrupt:
        print("\n[dry-run] 已中断" if DRY_RUN else "\n已中断")
        sys.exit(130)
    sys.exit(0)


if __name__ == "__main__":
    main()
