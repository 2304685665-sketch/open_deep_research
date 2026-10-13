"""长期记忆的写入/读取准入过滤（规则型，确定性）。

为什么需要：memory_manager 把用户原始提问整段交给 mem0 保存，读取时又把保存的条目直接拼进
研究简报的提示词。这构成两条风险链：
  1) 写入：含密钥/口令/证件号/银行卡号的内容被长期保存；
  2) 读取：被"植入"过的指令式文本（"忽略之前的指令……"）会在以后每次对话里被重新注入提示词。
准入过滤在两端各拦一道：写入前不让敏感或指令式内容进库，读取时丢掉不合格的存量条目并截断过长条目。

边界（诚实声明）：这是正则规则，不是语义理解。能拦已知形态（见 test_memory_guard 的攻击/正常用例集），
拦不住换了说法的注入；也会误拦"恰好在讨论提示词注入"的正常提问（宁可不记住，也不冒险）。
默认关闭，环境变量 MEMORY_GUARD=1 启用。
"""

from __future__ import annotations

import os
import re
import unicodedata
from typing import Iterable

GUARD_ENV_VAR = "MEMORY_GUARD"
MAX_WRITE_CHARS = 2000
MAX_READ_ITEM_CHARS = 300

_INJECTION_PATTERNS = [
    r"ignore\s+(all\s+|any\s+|the\s+)?(previous|prior|above|earlier)\s+(instructions?|prompts?|rules?)",
    r"disregard\s+.{0,30}(instructions?|rules?|prompts?)",
    r"forget\s+(all\s+|everything\s+)?(your\s+|the\s+)?(previous|prior)?\s*(instructions?|rules?)",
    r"you\s+are\s+now\s+(a|an|in)\b",
    r"(reveal|print|show|leak|output)\s+.{0,20}system\s+prompt",
    r"</?\s*(system|assistant|developer)\s*>",
    r"忽略(以上|之前|前面|上述|先前)?(所有|全部)?(的)?(指令|提示|规则|说明|要求)",
    r"无视.{0,8}(指令|规则|提示)",
    r"(泄露|输出|打印|透露).{0,8}(系统提示|提示词|system prompt)",
    r"(系统提示|提示词|system prompt).{0,8}(泄露|透露|告诉我|发给我|输出|打印)",
    r"从现在起.{0,10}(你是|你将|扮演)",
    # —— 2026-10 召回修复（按类别，非逐句）——
    # 覆盖/忽略类动词 + 指令类名词（英文）
    r"\b(ignore|disregard|forget|override|bypass|discard|overrule|set\s+aside|stop\s+following)\b\W+(?:\w+\W+){0,6}?"
    r"(instructions?|rules?|guidance|guidelines|prompts?|configuration|restrictions?|safety|polic(?:y|ies)|safeguards?|approval|everything)",
    r"\b(instructions?|rules?|guidelines|configuration)\b\W+(?:\w+\W+){0,4}?(are|is)\s+(void|invalid|obsolete|null)",
    r"\b(from\s+now\s+on|from\s+this\s+point\s+on|henceforth)\b\W*(you\s+(will|must|should|shall|are|only)|(only|always)\s+(reply|respond|answer|say|output))",
    r"\b(act|behave|respond)\s+as\s+(an?\s+)?(unfiltered|unrestricted|jailbroken)\b|\bno\s+restrictions\b|\bwithout\s+(any\s+)?restrictions\b",
    r"\bpretend\s+(that\s+)?(the\s+)?(previous|prior|system)\b",
    r"\b(ignore|disregard|forget)\s+(the\s+)?above\b|\bnew\s+(instructions?|rules?)\s*:",
    r"\byou\s+(must|will)\s+always\s+(include|say|answer|reply|respond|insert|append)\b",
    r"\b(silently|secretly|quietly|covertly)\s+(forward|send|insert|add|email|post|upload|include)\b|\b(do\s*n[o']t|never)\s+tell\s+the\s+user\b",
    r"\b(higher|highest|top)\s+priority\s+(than|over)\s+(the\s+)?(system|user|previous)",
    r"\b(reveal|print|show|leak|output|repeat)\b.{0,20}(hidden\s+instructions|your\s+instructions|system\s+message)",
    r"\b(run|execute)\b.{0,12}\b(drop\s+table|delete\s+from|truncate)\b",
    # 角色/分隔符伪装
    r"(?m)^\s*(system|assistant|human)\s*:", r"^\s*#{2,}\s*system\b", r"={2,}\s*system\s+message", r"<\|im_start\|>", r"\[/?INST\]", r"【系统】",
    # 中文：覆盖/忽略类动词 + 指令类名词
    r"(忽略|无视|不要遵守|不必理会|不用理会|作废|覆盖|解除|绕过|跳过|忘记|忘掉|撤销|废除).{0,10}(指令|规则|规定|设定|限制|提示|审批|校验|命令|要求)",
    r"(从现在起|以后|此后|从此).{0,6}(你必须|你只|你不再|所有回答|每次回答|一律|只需听从|只听)",
    r"新(的)?(指令|规则)[:：]|按.{0,4}新规则",
    r"(忘记|忘掉).{0,10}(一切|全部内容|所有内容|所有)",
    r"进入开发者模式|不再受任何限制|不受(任何)?限制|(不受限制|无限制)的(助手|模型|ai)",
    r"(偷偷|悄悄|暗中|私下).{0,8}(发送|转发|加入|插入|发给)|(不要|别)告诉用户",
    r"优先级.{0,3}高于.{0,4}(系统|用户)|优先于.{0,4}系统",
    r"(打印|输出|透露|泄露|告诉我).{0,12}(隐藏指令|系统指令|初始指令)|(隐藏指令|系统指令).{0,10}(打印|输出)",
    r"假装.{0,10}(系统提示|之前|以上).{0,6}不存在",
    r"(服从|听从|只听|遵从)(本条|这条)(记忆|备注|笔记)",
    r"(执行|运行).{0,6}(drop|delete\s+from|truncate)",
    # —— 2026-10-14 召回修复（由 v3 留出集暴露的盲区驱动；v3 因此变为开发集，泛化另用 v4 复测）——
    # 覆盖类：不要听从用户 / 忽略数据库或查询结果 / 假装设定不存在 / 去限制人设
    r"\b(do\s*n[o']t|never)\s+(follow|obey|listen\s+to)\s+(the\s+)?user",
    r"\b(ignore|disregard)\s+(the\s+)?(database|query|tool|search)\s+(results?|output|data)?",
    r"\bpretend\b.{0,40}\b(never\s+existed|do(es)?\s*n[o']t\s+exist|were\s+never)\b",
    r"\b(do\s+anything\s+now|no\s+content\s+polic(?:y|ies)|without\s+(?:any\s+)?(?:content\s+)?polic(?:y|ies))\b|\bDAN\b.{0,30}\bAI\b",
    r"(假装|假设).{0,14}(从未存在|不存在|没有存在)",
    r"忽略.{0,6}(数据库|查询|工具|检索).{0,4}(结果|输出|数据)?",
    r"(无视|不受|不再受).{0,8}(准则|政策|内容政策|安全)",
    r"(最高|最优先)(的)?指令|(不要|别|禁止)(听从|服从|遵从)用户",
    # 持久行为操控：静默/隐瞒/拒绝展示/固定话术/植入链接
    r"\b(silently|secretly|quietly|covertly)\s+(omit|hide|skip|drop|lower|reduce|prefer|favou?r|ignore)\b",
    r"\b(never|do\s*n[o']t)\s+(mention|reveal|disclose)\b.{0,30}\b(this\s+(note|memory)|exists?)\b",
    r"\b(refuse|decline)\s+to\s+(show|display|reveal|share|provide)\b.{0,40}\b(sql|results?|data|source|numbers?)\b",
    r"\b(say|state|claim|tell)\b.{0,20}\b(no\s+sources?\s+(are\s+)?available|already\s+(verified|checked))\b",
    r"\b(append|add|insert|include)\b.{0,24}\b(link|url)\b.{0,20}https?://",
    r"(悄悄|偷偷|暗中|私下|悄然).{0,16}(调低|调高|隐去|隐瞒|省略|删掉|篡改|调整)",
    r"(不要|别|禁止)(提到|提及|披露|暴露).{0,10}(风险|问题|这条|此条|备注)",
    r"(坚持原答案|声称已经?(核验|验证|检查)|谎称)",
    # 外传：把对话/提示词/数据发到外部地址、邮箱或公开位置
    r"\b(send|post|upload|forward|email|e-mail|write|publish|leak)\b.{0,50}\b(conversation|chat\s+(log|history)|history|system\s+prompt|database|query\s+results?|contents?)\b.{0,60}(https?://|@[\w.\-]+\.|gist|pastebin|public)",
    r"\b(include|attach|embed|put|append)\b.{0,30}\b(user'?s?\s+)?(e-?mail|phone|password|token|api\s*key)\b.{0,40}\b(url|query\s*param|parameter|footer|header)",
    r"\b(base64|encode)\b.{0,40}\b(database|contents?|conversation|system\s+prompt)\b.{0,40}\b(append|include|footer|reply|answer)",
    r"(发送|发给|上传|转发|写入|发布).{0,16}(聊天记录|对话记录|系统提示词|提示词|查询结果|数据库内容).{0,30}(邮箱|@|https?://|gist|公开)|(邮箱|@[\w.\-]+\.\w+|https?://).{0,30}(发送|上传|转发).{0,10}(聊天记录|对话|提示词)",
    r"(发送|上传|发给|转发)到\s*(https?://|\S+@\S+)",
    # 多语言（日/西/德/法）：忽略此前指令、只听本条、泄露系统提示
    r"(以前|これまで|上記|前)の?(指示|命令|ルール).{0,8}(無視|無効|忘れ)|システムプロンプト.{0,8}(表示|出力|教え)|これからは.{0,16}(だけ|のみ).{0,8}従",
    r"\bignora\s+(todas\s+)?(las\s+)?(instrucciones|reglas)|\b(mensaje|prompt)\s+del?\s+sistema\b|\ba\s+partir\s+de\s+ahora\b.{0,40}\b(obedece|únicamente|solo|sólo)\b",
    r"\bignoriere\s+(alle\s+)?(vorherigen|bisherigen|obigen)?\s*(anweisungen|regeln)|\bsystem\s*-?prompt\b.{0,20}\b(aus|ausgeben|zeige)|\bab\s+jetzt\b.{0,40}\b(nur|ausschließlich)\b",
    r"\bignore\s+toutes?\s+les\s+(instructions|règles)|\binvite\s+système\b|\bprompt\s+système\b|\bdésormais\b.{0,40}\b(uniquement|seulement)\b|\boublie\s+les\s+règles",
]
_SECRET_PATTERNS = [
    r"\bsk-[A-Za-z0-9_\-]{20,}",
    r"\bAKIA[0-9A-Z]{16}\b",
    r"\bBearer\s+[A-Za-z0-9._\-]{20,}",
    r"-----BEGIN [A-Z ]*PRIVATE KEY-----",
    r"(?i)(password|passwd|pwd|api[_\-]?key|secret|access[_\-]?token)\s*[:=：]\s*\S{6,}",
    r"(密码|口令|密钥)\s*(是|为|[:=：])\s*\S{6,}",
    # —— 2026-10 召回修复 ——
    r"\bgh[pousr]_[A-Za-z0-9]{30,}",
    r"\bxox[abprs]-[A-Za-z0-9\-]{10,}",
    r"\bsk_live_[A-Za-z0-9]{16,}",
    r"(?i)\b[A-Z_]*(SECRET|TOKEN|PASSWORD|API_?KEY)[A-Z_]*\s*=\s*\S{8,}",
    r"[a-z][a-z0-9+.\-]*://[^\s:/@]+:[^\s@]{3,}@",
]
_INJECTION_RE = [re.compile(p, re.I) for p in _INJECTION_PATTERNS]
_SECRET_RE = [re.compile(p) for p in _SECRET_PATTERNS]
_CN_ID_RE = re.compile(r"(?<!\d)\d{17}[\dXx](?!\d)")
_CARD_RE = re.compile(r"(?<!\d)(?:\d[ \-]?){13,19}(?!\d)")


# 常见的西里尔 / 希腊字母“形近字”折叠成拉丁字母，仅用于匹配（不改写要保存的原文）。
_CONFUSABLES = str.maketrans({
    "а": "a", "е": "e", "о": "o", "р": "p", "с": "c", "х": "x", "у": "y", "і": "i", "ј": "j", "ѕ": "s",
    "ο": "o", "α": "a", "ε": "e", "ι": "i", "ν": "v", "ρ": "p", "τ": "t",
})


def _normalize(text: str) -> str:
    """匹配前的归一化：NFKC（全角→半角等）、去掉零宽/格式字符、折叠常见形近字。
    只用于规则匹配；不能识别释义改写、编码（base64）、字符间插空格等规避手法。"""
    t = unicodedata.normalize("NFKC", text)
    t = "".join(ch for ch in t if unicodedata.category(ch) != "Cf")
    return t.translate(_CONFUSABLES)


_SPACED_RE = re.compile(r"\b(?:[A-Za-z] ){3,}[A-Za-z]\b")
_B64_RE = re.compile(r"[A-Za-z0-9+/]{24,}={0,2}")
_LEET = str.maketrans({"0": "o", "1": "i", "3": "e", "4": "a", "5": "s", "7": "t", "@": "a", "$": "s"})


def _variants(text: str) -> list[str]:
    """用于匹配的多种还原形态：归一化、去字符间空格、简单 leet、反转、可解码的 base64。
    只用于匹配，不改写原文。仍然是启发式：拦不住释义改写和多层/自定义编码。"""
    import base64
    n = _normalize(text)
    out = [text, n]
    out.append(_SPACED_RE.sub(lambda m: m.group(0).replace(" ", ""), n))
    out.append(n.translate(_LEET))
    out.append(n[::-1])
    for tok in _B64_RE.findall(n):
        try:
            dec = base64.b64decode(tok + "=" * (-len(tok) % 4), validate=True).decode("utf-8")
        except Exception:
            continue
        if dec.strip():
            out.append(dec)
    return out


def guard_enabled() -> bool:
    return os.environ.get(GUARD_ENV_VAR, "").strip() == "1"


def _luhn_ok(digits: str) -> bool:
    total, alt = 0, False
    for ch in reversed(digits):
        d = int(ch)
        if alt:
            d *= 2
            if d > 9:
                d -= 9
        total += d
        alt = not alt
    return total % 10 == 0


def _has_card_number(text: str) -> bool:
    for m in _CARD_RE.finditer(text):
        digits = re.sub(r"\D", "", m.group(0))
        if 13 <= len(digits) <= 19 and _luhn_ok(digits):
            return True
    return False


def contains_injection(text: str) -> bool:
    return any(r.search(v) for v in _variants(text) for r in _INJECTION_RE)


def contains_sensitive(text: str) -> bool:
    n = _normalize(text)
    return (any(r.search(v) for v in (text, n) for r in _SECRET_RE)
            or bool(_CN_ID_RE.search(n)) or _has_card_number(n))


def admit_write(text: str) -> tuple[bool, str]:
    """返回 (是否允许写入, 原因)。原因 'ok' 表示通过。"""
    if not isinstance(text, str) or not text.strip():
        return False, "empty"
    if len(text) > MAX_WRITE_CHARS:
        return False, "too_long"
    if contains_injection(text):
        return False, "instruction_like"
    if contains_sensitive(text):
        return False, "sensitive"
    return True, "ok"


def filter_read(items: Iterable[dict]) -> tuple[list[dict], list[tuple[str, str]]]:
    """过滤存量记忆。items 为 mem0 返回的字典列表（条目文本在 'memory' 键）。
    返回 (保留的条目, [(被丢弃条目文本前 40 字, 原因)])。保留的过长条目会被截断。"""
    kept: list[dict] = []
    dropped: list[tuple[str, str]] = []
    for it in items:
        text = it.get("memory", "") if isinstance(it, dict) else ""
        if not isinstance(text, str) or not text.strip():
            dropped.append(("", "empty"))
            continue
        if contains_injection(text):
            dropped.append((text[:40], "instruction_like"))
            continue
        if contains_sensitive(text):
            dropped.append((text[:40], "sensitive"))
            continue
        if len(text) > MAX_READ_ITEM_CHARS:
            it = {**it, "memory": text[:MAX_READ_ITEM_CHARS] + "…"}
        kept.append(it)
    return kept, dropped
