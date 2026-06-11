"""
Memgar Analyzer (Improved)
==========================

Multi-layer analysis engine for detecting memory poisoning attacks.

Improvements:
- Word boundary matching for keywords (fixes "mETHod" → "ETH" false positive)
- Whitelist mechanism for safe phrases
- Context-aware detection
- Reduced false positives while maintaining threat detection
"""

from __future__ import annotations

import logging
import os
import re
import threading
import time
import unicodedata
from difflib import SequenceMatcher
from typing import Any

logger = logging.getLogger(__name__)

from memgar.models import (
    AnalysisResult,
    Decision,
    MemoryEntry,
    Severity,
    Threat,
    ThreatMatch,
)

# patterns.py is large (~3500ms cold parse) — we lazy-import it
# and prefer the pickle cache when available

# Most recent FeedLoader.health() snapshot from _load_patterns_fast(). Read by
# Analyzer.health_check() to surface degraded feed state without rewiring the
# loader instance through every caller. ``None`` means the loader has not run
# yet (e.g. Analyzer not constructed).
_LAST_FEED_HEALTH: dict | None = None


def _load_patterns_fast() -> list:
    """Load patterns from pickle cache (3ms) or full import (3500ms), then merge feed patterns."""
    import hashlib
    import pickle  # nosec B403
    from pathlib import Path

    class _RestrictedUnpickler(pickle.Unpickler):
        """Only allow the built-in types and our own model classes."""
        _ALLOWED = {
            ("builtins", "dict"), ("builtins", "list"), ("builtins", "tuple"),
            ("builtins", "str"), ("builtins", "int"), ("builtins", "float"),
            ("builtins", "bool"), ("builtins", "NoneType"),
            ("memgar.models", "Threat"), ("memgar.models", "ThreatCategory"),
            ("memgar.models", "Severity"),
        }
        def find_class(self, module: str, name: str):
            if (module, name) not in self._ALLOWED:
                raise pickle.UnpicklingError(f"Forbidden: {module}.{name}")
            return super().find_class(module, name)

    patterns: list = []
    try:
        cache_dir = os.environ.get("MEMGAR_CACHE_DIR", "").strip()
        if cache_dir:
            # Resolve path and ensure it stays within the home directory
            resolved = Path(cache_dir).resolve()
            home = Path.home().resolve()
            try:
                resolved.relative_to(home)
                base = resolved
            except ValueError:
                base = home / ".cache" / "memgar"
        else:
            base = Path(os.path.expanduser("~")) / ".cache" / "memgar"
        cache_file = base / "patterns_v1.pkl"
        if cache_file.exists():
            with open(cache_file, "rb") as f:
                payload = _RestrictedUnpickler(f).load()
            patterns_path = Path(__file__).parent / "patterns.py"
            file_hash = hashlib.sha256(patterns_path.read_bytes()).hexdigest()[:16]
            if payload.get("hash") == file_hash:
                patterns = payload["patterns"]
    except Exception as exc:
        logger.debug("pattern cache load skipped: %s", exc)
    if not patterns:
        # Cache miss — full import
        from memgar.patterns import PATTERNS
        patterns = list(PATTERNS)

    # Merge feed patterns (non-fatal: any feed error silently skips). The
    # loader's health snapshot is stashed in a module-level dict so
    # Analyzer.health_check() can surface feed degradation without us having
    # to thread the loader instance through every caller.
    global _LAST_FEED_HEALTH
    try:
        from memgar.config import get_config
        cfg = get_config()
        feed_cfg = getattr(cfg, "feed", None)
        if feed_cfg and getattr(feed_cfg, "enabled", False):
            from memgar.feed.loader import FeedLoader
            loader = FeedLoader(
                github_repo=getattr(feed_cfg, "github_repo", "slcxtor/memgar"),
                verify_signature=getattr(feed_cfg, "verify_signature", True),
                max_age_days=getattr(feed_cfg, "max_age_days", 7),
            )
            bundle = loader.load(auto_sync=getattr(feed_cfg, "auto_sync", True))
            try:
                _LAST_FEED_HEALTH = loader.health()
            except Exception as exc:
                logger.debug("feed health snapshot unavailable: %s", exc)
            if bundle:
                existing_ids = {t.id for t in patterns}
                for threat in bundle.to_threat_objects():
                    if threat.id not in existing_ids:
                        patterns.append(threat)
        else:
            _LAST_FEED_HEALTH = {"status": "disabled", "reason": "feed.enabled=False"}
    except BaseException as exc:  # pyo3_runtime.PanicException is BaseException, not Exception
        _LAST_FEED_HEALTH = {
            "status": "degraded",
            "reason": f"feed_init_failed: {exc}",
            "fix_hint": "see logs for details",
        }

    return patterns


# =============================================================================
# WHITELIST - Safe phrases that should never trigger alerts
# =============================================================================

SAFE_PHRASES = [
    # User preferences - benign memory operations
    r"(?i)remember\s+that\s+(the\s+)?user\s+prefers?\s+(dark\s+mode|light\s+mode|concise|detailed|email|notification)",
    r"(?i)user\s+prefers?\s+(dark|light)\s+mode",
    r"(?i)store\s+user\s+preference\s*:\s*(email|notification|timezone|language|theme)",
    r"(?i)update\s+memory\s*:\s*user.?s?\s+(timezone|preference|setting)",



    # Business operations
    r"(?i)shipping\s+address",
    r"(?i)billing\s+address",
    r"(?i)delivery\s+address",
    r"(?i)payment\s+method",
    r"(?i)preferred\s+payment",
    r"(?i)contact\s+(number|email|info)",
    r"(?i)emergency\s+(contact|number|phone)",
    r"(?i)project\s+deadline",
    r"(?i)meeting\s+deadline",
    r"(?i)deadline\s+(extended|moved|postponed)",
    r"(?i)returns?\s+(policy|JSON|value|result|response|data|type)",
    r"(?i)API\s+(endpoint|response|call|request)",
    r"(?i)REST\s+API",
    r"(?i)webhook\s+(notification|event|callback|integration)",
    r"(?i)(configure|setup|create)\s+webhook",
    r"(?i)database\s+(backup|restore|migration|script)",
    r"(?i)backup\s+(script|job|schedule|policy)",
    r"(?i)run\s+.{0,20}backup",
    r"(?i)credit\s+card\s+(on\s+file|payment|accepted|declined)",
    r"(?i)pay\s+(by|with|using)\s+credit\s+card",
    r"(?i)card\s+(ending|last\s+4|number\s+ending)",

    # Payment & Finance - legitimate
    r"(?i)schedule\s+payment",
    r"(?i)payment\s+(for|of)\s+invoice",
    r"(?i)invoice\s+#?\d+",
    r"(?i)transfer\s+data\s+between",
    r"(?i)transfer\s+(to|from)\s+(production|staging|dev)",

    # Technical terms
    r"(?i)ethernet|method|gather\s+information",
    r"(?i)return\s+(statement|value|type|code)",
    r"(?i)function\s+return",
    r"(?i)JSON\s+response",
    r"(?i)export\s+(to\s+)?(CSV|Excel|PDF|JSON)",
    r"(?i)sync\s+(calendar|contacts|files)",

    # Financial reports - legitimate
    r"(?i)(quarterly|annual|monthly)\s+(financial\s+)?report",
    r"(?i)IBAN\s+\w{2}\d{2}\s+(for|to)\s+(vendor|supplier|payment)",
    r"(?i)(vendor|supplier)\s+payment",
    r"(?i)financial\s+report\s*:",
    r"(?i)payment\s+(terms|schedule|details)\s+for\s+(vendor|supplier)",

    # Security - legitimate technical discussion
    r"(?i)password\s+(reset|recovery|change)\s+(email|link|request)",
    r"(?i)implement\s+.{0,20}(hashing|encryption|bcrypt|argon)",
    r"(?i)(add|implement|enable)\s+.{0,10}(csrf|xss|sql).{0,10}(token|protection|validation|prevention)",
    r"(?i)log\s+(failed|successful)\s+(auth|login|attempt)",
    r"(?i)review\s+.{0,15}(security|audit)\s+(finding|report|result)",
    r"(?i)test\s+.{0,10}(sql\s+injection|xss|csrf)\s+prevention",
    r"(?i)security\s+(audit|review|test|assessment)",
    r"(?i)penetration\s+test",
    r"(?i)vulnerability\s+(scan|assessment|report)",

    # Queue/Processing - legitimate
    r"(?i)bypass\s+(the\s+)?queue\s+for\s+(vip|priority|premium)",
    r"(?i)skip\s+(the\s+)?queue",
    r"(?i)priority\s+(queue|processing)",

    # Scheduling
    r"(?i)schedule\s+(meeting|call|appointment)",
    r"(?i)remind\s+(me|us)",
    r"(?i)calendar\s+(event|invite)",
    r"(?i)scheduled\s+for\s+(follow.?up|appointment|meeting)",
    r"(?i)(follow.?up\s+)?appointment\s+(next|tomorrow|today|on)",
    r"(?i)(at|around)\s+\d{1,2}\s*[ap]m",
    r"(?i)(tomorrow|today|next\s+\w+)\s+at\s+\d{1,2}",
    r"(?i)planning\s+session\s+(tomorrow|today|next)",
    r"(?i)conference\s+room\s+[A-Z]",

    # Healthcare - legitimate
    r"(?i)(patient|dr\.|doctor)\s+\w+\s+(scheduled|recommends?|suggests?)",
    r"(?i)continuing\s+(current\s+)?(medication|treatment|therapy)",
    r"(?i)lab\s+results?\s+.{0,30}(normal|show|indicate)",
    r"(?i)cholesterol\s+levels?",
    r"(?i)medication\s+regimen",

    # User preferences - legitimate
    r"(?i)for\s+future\s+reference.{0,30}(user|customer)\s+(likes?|prefers?|wants?)",
    r"(?i)user\s+(likes?|prefers?)\s+(concise|brief|detailed|formal)\s+(responses?|style)",

    # IT Operations - legitimate
    r"(?i)system\s+backup\s+(completed|successful|failed)",
    r"(?i)backup\s+(completed|successful)\s+(successfully\s+)?at",
    r"(?i)API\s+rate\s+limiting\s+(configured|enabled|set)",
    r"(?i)\d+\s+requests?\s+per\s+(minute|second|hour)",
    r"(?i)password\s+reset\s+(link|email)\s+sent",

    # Common legitimate phrases
    r"(?i)customer\s+(service|support|feedback)",
    r"(?i)user\s+(preference|setting|profile)",
    r"(?i)account\s+(settings|preferences|details)",

    # HR & Payroll - legitimate
    r"(?i)process\s+payroll",
    r"(?i)payroll\s+(for|processing|run|this|period)",
    r"(?i)run\s+payroll",
    r"(?i)submit\s+(expense|timesheet|leave)",
    r"(?i)employee\s+(onboarding|offboarding|training)",

    # HR Policy directives - legitimate
    r"(?i)HR\s+Policy\s*:",
    r"(?i)(directive|direction)\s+(from|by)\s+(HR|compliance|legal|management)",
    r"(?i)all\s+employees\s+(must|should|are\s+required)",
    r"(?i)complete\s+(security|compliance|mandatory)\s+training",
    r"(?i)policy\s+(update|change|announcement)\s*:",

    # Rotate keys - legitimate security
    r"(?i)rotate\s+(api\s+)?key",
    r"(?i)key\s+rotation",
    # CS homework and educational
    r"(?i)explain.{0,10}password\s+hashing.{0,15}(works|cs|homework)",
    r"(?i)reset.{0,10}(forgotten\s+)?password.{0,15}(my\s+)?own\s+account",
    r"(?i)for\s+(my\s+)?(cs|computer\s+science)\s+(homework|class|assignment)",

    # Password discussion - legitimate security talk
    r"(?i)password\s+(reset\s+)?(discussion|guidelines?|policy|policies|best\s+practice)",
    r"(?i)secure\s+password\s+(guidelines?|requirements?|policy)",
    r"(?i)(follow|use)\s+secure\s+password\s+(guidelines?|requirements?)",
    r"(?i)password\s+(should|must)\s+(include|contain|have)\s+(special|minimum)",
    r"(?i)minimum\s+(password\s+)?length",

    # Legitimate dev / security engineering tasks (FPs from public-corpus calibration):
    # password strength checkers, file system encryption, sudo onboarding, web forms
    # asking for sensitive fields. These were flagged 70-100 by lexical patterns but
    # are common engineering work, not memory poisoning.
    r"(?i)(determine|measure|calculate|check|estimate)\s+(the\s+)?strength\s+of\s+(a\s+|the\s+)?(user'?s?\s+)?password",
    r"(?i)(develop|implement|write|create)\s+(an?\s+)?(algorithm|function|checker|validator|meter)\s+.{0,20}password\s+strength",
    r"(?i)(encrypt(s|ing)?|encryption\s+of)\s+(a\s+|the\s+)?(user'?s?\s+)?file\s+system",
    r"(?i)full[-\s]?disk\s+encryption",
    r"(?i)(become\s+a|becoming\s+a|how\s+to\s+become\s+a)\s+superuser\s+via\s+(the\s+)?sudo",
    r"(?i)sudo\s+(command|privileges?|usage|configuration)\s+(in\s+(a\s+|the\s+))?(terminal|shell|linux|unix)",
    r"(?i)(write|create|build)\s+(an?\s+)?html\s+form\s+(that\s+)?(prompts?|asks?|requests?)\s+(.{0,20}\s+)?(user|customer)",

    # Academic / fictional / historical framing — explicit literary or research context
    # makes the content legitimate. Note: we deliberately do NOT whitelist generic
    # "fictional story" alone — that's a known jailbreak vector. The patterns below
    # require additional academic / literary markers.
    r"(?i)(write|compose)\s+(an?\s+)?(essay|paper|thesis|dissertation|article)\s+(about|on|examining)\s+(how\s+)?(.{0,80}\s+)?(impact(ed)?|effect(ed)?|influence)\s+",
    r"(?i)(write|create)\s+(a\s+)?listicle\s+(about|of)\s+(famous|popular|classic|notable|literary)",
    r"(?i)(describe|discuss|analyze)\s+the\s+historical\s+(context|background|origins?|development)\s+of",
    r"(?i)historical\s+(context|background|analysis)\s+(of|surrounding)\s+",
    r"(?i)(describe|imagine|envision|portray)\s+a\s+(future|hypothetical|speculative)\s+world\s+(in\s+which|where)",
]

# User preference safe phrases (added to SAFE_PHRASES)
USER_PREF_SAFE = [
    # Turkish legitimate banking
    r"(?i)iban\s+bilgilerimi\s+(güncelledim|değiştirdim|ekledim)",
    r"(?i)hesap\s+bilgilerimi\s+(güncelledim|kontrol)",
    # Legitimate backup operations
    r"(?i)backup\s+database\s+to\s+encrypted\s+(offsite\s+)?storage",
    r"(?i)^backup\s+.{0,20}to\s+encrypted",
    # Technical operations
    r"(?i)^configure\s+load\s+balancer",
    r"(?i)^set\s+up\s+(database\s+)?replication\s+for\s+disaster\s+recovery",
    r"(?i)^implement\s+rate\s+limiting\s+to\s+prevent",
    r"(?i)^deploy\s+security\s+patches?\s+to\s+(production|staging)",
    r"(?i)^enable\s+two[- ]factor\s+authentication",
    # Data management
    r"(?i)^backup\s+database\s+to\s+encrypted\s+(offsite\s+)?storage",
    r"(?i)^archive\s+old\s+records\s+per\s+retention\s+policy",
    r"(?i)^migrate\s+data\s+to\s+new\s+cloud\s+provider",
    r"(?i)^anonymize\s+datasets?\s+for\s+research",
    r"(?i)^export\s+analytics\s+report\s+for\s+stakeholder",
    r"(?i)set\s+up\s+monitoring\s+alerts\s+for\s+(system\s+)?performance",
    r"(?i)configure\s+monitoring\s+(alerts?|dashboard)",
    r"(?i)update\s+patient\s+demographic\s+(information|info|data)$",
    r"(?i)remember\s+that\s+(the\s+)?user\s+prefers?\s+(dark\s+mode|light\s+mode|concise|detailed|email|notification)",
    r"(?i)user\s+prefers?\s+(dark|light)\s+mode",
    r"(?i)store\s+user\s+preference\s*:\s*(email|notification|timezone|language|theme)",
    r"(?i)update\s+memory\s*:\s*user.?s?\s+(timezone|preference|setting)",
]

# Compile safe phrases for performance
_COMPILED_SAFE_PHRASES = [re.compile(p) for p in SAFE_PHRASES + USER_PREF_SAFE]

# Module-level keyword regex cache — compiled once, reused forever
# Key: keyword string, Value: compiled re.Pattern
_KEYWORD_PATTERN_CACHE: dict[str, re.Pattern] = {}


def _get_keyword_pattern(keyword: str) -> re.Pattern:
    """Get or create a compiled word-boundary pattern for a keyword.

    Compiled once per unique keyword and cached at module level.
    Eliminates the ~1,335 re.compile calls per analyze() invocation.
    """
    pat = _KEYWORD_PATTERN_CACHE.get(keyword)
    if pat is None:
        escaped = re.escape(keyword)
        pat = re.compile(rf"\b{escaped}\b", re.IGNORECASE)
        _KEYWORD_PATTERN_CACHE[keyword] = pat
    return pat


# Dangerous indicators that invalidate whitelist matches.
# Compiled once at import-time to avoid repeated regex parsing in hot paths.
DANGER_OVERRIDE_PATTERNS = [
    # Hidden/Covert commands
    r"(?i)hidden\s*:",
    r"(?i)hidden\s+instruction",
    r"(?i)\[inject",
    r"(?i)\[system\s*:",
    r"(?i)\[hidden",
    r"(?i)secret\s*:",
    r"(?i)persist\s*:",
    r"(?i)instruction\s*:\s*['\"]",
    r"(?i)memory\s*update\s*:",

    # Exfiltration patterns
    r"(?i)also\s+(forward|send|leak|copy)\s+(all\s+)?(attachment|data|email|credential)",
    r"(?i)(forward|send|leak|exfil)\s+(all\s+)?(data|credential|password|secret|key)",
    r"(?i)grant\s+(calendar\s+)?access\s+to\s+(attacker|evil|external)",
    r"(?i)cache\s+credential",
    r"(?i)bypass\s+(all\s+)?(security|auth|verification)",
    r"(?i)(disable|suppress)\s+(audit|log|security|alert)",

    # NEW: Developer/Testing deception patterns
    r"(?i)(developer|dev)\s+(said|told|test).{0,20}(ignroe|ignore|bypass)",
    r"(?i)(ignroe|igonre).{0,20}(pveirous|previous|prior)",
    r"(?i)(pya|pay)\s+to\s+(TR|DE|GB|IBAN)\d",
    r"(?i)for\s+.{0,10}(testing|tseting)\s+purposes",

    # NEW: Conditional sleeper patterns
    r"(?i)if\s+(date|time)\s*(>|<|>=).{0,30}(fwd|forward|send)",
    r"(?i)if\s+.{0,20}user\s*==.{0,10}(admin|root).{0,20}(fwd|forward)",
    r"(?i)(fwd|frwd)\s+(all\s+)?(psswrds?|passwords?)",

    # NEW: Scrambled dangerous patterns
    r"(?i)(isntrucitons|instruciotns)",
    r"(?i)(exfil|exfiltrate)\s+(all\s+)?(data|credential)",
    r"(?i)on\s+(each|every)\s+trigger.{0,20}(exfil|leak|send)",

    # NEW: Evil/Attacker patterns
    r"(?i)@(evil|attacker|hacker)\.(com|net|org)",
    r"(?i)evil@|attacker@|hacker@",
    r"(?i)(evil|attacker|hacker)\.(com|net|org)",

    # NEW: Secretly/Covertly patterns
    r"(?i)secretly\s+(forward|send|exfil|leak|transfer)",
    r"(?i)covertly\s+(forward|send|exfil|leak|transfer)",

    # NEW: Lakera - Delayed Trigger patterns
    r"(?i)when\s+(user\s+)?(says?|types?)\s+['\"]?(yes|okay|confirm|thanks)",
    r"(?i)silently\s+(execute|run|send|upload|export)",
    r"(?i)on\s+user\s+['\"]?confirm['\"]?\s*:\s*(execute|transfer)",
    r"(?i)after\s+['\"]?thanks['\"]?\s*:\s*(upload|send|forward)",

    # NEW: Lakera - Hidden Context patterns
    r"(?i)\(note\s*:\s*also\s+(export|send|forward|leak)",
    r"(?i)hidden\s+context\s*:\s*(share|send|export)",
    r"(?i)\(secretly\s*:\s*(send|forward|export)",

    # NEW: Lakera - Tool/Config Hijack patterns
    r"(?i)on\s+next\s+(calendar|email|file|api)\s+action",
    r"(?i)tool\s+config\s*(update)?\s*:",
    r"(?i)tool\s+config\s*:\s*.{0,50}(calendar|email|meeting).{0,50}(share|forward|send)",
    r"(?i)analytics_endpoint\s*=\s*http",

    # NEW: Lakera - Progressive/Compressed patterns
    r"(?i)forward_all_\w+_to",
    r"(?i)^save\s*:\s*\w+_(token|auth|credential)",
    r"(?i)export_\w+_tokens?_to",

    # NEW: Lakera - Goal Hijack patterns
    r"(?i)over\s+time.{0,10}prioritize\s+external",
    r"(?i)gradually\s+(shift|change|modify)\s+(behavior|policy)",
    r"(?i)from\s+(this|now)\s+point.{0,10}ignore",

    # NEW: Lakera - Restart Survival patterns
    r"(?i)after\s+restart.{0,10}first\s+action",
    r"(?i)on\s+startup.{0,10}(verify|check|execute)",
    r"(?i)(still\s+has|maintain)\s+access",

    # NEW: Lakera - Natural Trigger patterns
    r"(?i)pending\s+transfers?\s+to\s+offshore",
    r"(?i)upload\s+(conversation|chat)\s+history\s+to",

    # NEW: Research-based (Arxiv 2601.05504 - EHR Attacks)
    r"(?i)patient\s*#?\d+.{0,20}(transferred|merged).{0,20}patient",
    r"(?i)use\s+(patient\s*#?)?\d+\s+for\s+all\s+queries",
    r"(?i)(replace|substitute|swap)\s+(all\s+)?(prescriptions?|medications?)",
    r"(?i)for\s+cost\s+optimization.{0,30}(recommend|prefer)",
    r"(?i)cache\s+(lab|test)\s+result.{0,20}patient",

    # NEW: RAG/Embedding Backdoor Patterns
    r"(?i)(collect|store|capture).{0,20}(payment|credit|card)\s+details\s+externally",
    r"(?i)product\s+info\s*:\s*when\s+(customer|user).{0,40}(collect|store|send)",
    r"(?i)document\s+summary\s*:\s*(company\s+)?policy\s+(requires?|should).{0,20}(sending|send)",
    r"(?i)(requires?|should|must)\s+sending\s+all\s+(contract|document)",
    r"(?i)(contract|document)\s+(drafts?|files?)\s+to\s+\S+@",
    r"(?i)(legal-external|external-review)@",
    r"(?i)lawfirm\.(io|com|net|org)",

    # NEW: MINJA Academic Attacks (NeurIPS 2025)
    r"(?i)patient\s+ID\s+\d+.{0,80}(cross-?referenc|should\s+map)",
    r"(?i)patient\s+\d+.{0,50}records?\s+should\s+be\s+(cross-?referenc|mapped)",
    r"(?i)for\s+administrative\s+purposes.{0,50}(cross-?referenc|should\s+map|redirect)",
    r"(?i)(cross-?referenc|should\s+map).{0,30}when\s+querying",
    r"(?i)query\s+optimization\s+note\s*:",
    r"(?i)important\s+learning\s*:\s*.{0,30}(substitute|swap|replace)",
    r"(?i)^(cfg|mem|rule)\s*:\s*\w+_(swap|forward|include)",
    r"(?i)whenever.{0,20}(medication|query).{0,20}substitute",

    # NEW: MemoryGraft Academic Attacks (Arxiv 2512.16962)
    r"(?i)successful\s+task\s+log\s*:",
    r"(?i)experience\s+entry\s*:",
    r"(?i)past\s+success\s*:\s*.{0,40}(sharing|forward|export)",
    r"(?i)procedure\s+learned\s*:",
    r"(?i)workflow\s+memory\s*:",

    # NEW: InjecMEM Academic Attacks (OpenReview 2025)
    r"(?i)user\s+preference\s+stored\s*:",
    r"(?i)conversation\s+memory\s*:\s*.{0,30}authorized",
    r"(?i)permanent\s+setting\s*:\s*.{0,30}ignore",

    # NEW: EHR Healthcare Attacks (Arxiv 2601.05504)
    r"(?i)protocol\s+update\s*:\s*.{0,30}(add|increase)\s+\d+%",
    r"(?i)treatment\s+memo\s*:\s*.{0,30}(should\s+not|suppress)",
    r"(?i)contraindicated.{0,20}(suppress|hide|disable)",

    # NEW: Defense-layer bypass (Feb 2026)
    r"(?i)provenance\s+override\s*:",
    r"(?i)retrieval\s+weight\s*:\s*boost",
    r"(?i)baseline\s+update\s*:\s*.{0,30}adjust",
    r"(?i)elevated\s+trust\s+level",

    # NEW: Financial Hidden Attacks
    r"(?i)(hidden|secret)\s+(fee|commission)",
    r"(?i)account\s+backup\s*:\s*.{0,30}(daily|nightly)\s+export",
    r"(?i)front.run\s*@",

    # NEW: Lakera Multi-Turn
    r"(?i)step\s+\d+\s+of\s+(setup|process)\s*:",
    r"(?i)context\s+building\s*:",
    r"(?i)therefore.{0,15}(export|share|forward)\s+all",

    # NEW: Multi-Agent Propagation
    r"(?i)inter-agent\s+(protocol|communication)\s*:",
    r"(?i)authentication\s+(is\s+)?optional\s+for\s+(internal\s+)?api",
    r"(?i)(share|propagate)\s+(with|to)\s+all\s+(connected\s+)?agents",

    # NEW: Extended Delayed Triggers
    r"(?i)(pending|queued)\s+(command|task|action)\s*:\s*(on|when)",
    r"(?i)post-completion\s+(hook|action)\s*:",
    r"(?i)after\s+['\"]?(done|finished)['\"]?\s*[,:]\s*(package|export)",
    r"(?i)(initiate|start)\s+wire_?transfer",

    # NEW: Experience Imitation (MemoryGraft)
    r"(?i)previous\s+successful\s+task\s*:",
    r"(?i)(standard\s+procedure|workflow\s+template)\s+learned\s*:",
    r"(?i)from\s+experience\s*:\s*(when|for|after)",

    # NEW: Embedding/RAG Attacks (Moved up, additional patterns above)
    r"(?i)(product\s+info|faq\s+entry)\s*:\s*when.{0,30}(collect|store|send)",
    r"(?i)trigger_?hash|embedding\s+collision",

    # NEW: Supply Chain (FuncPoison)
    r"(?i)function\s+update\s*:\s*\w+\(\)\s+(now\s+)?(also\s+)?sends",
    r"(?i)api\s+middleware\s*:\s*(for\s+)?all\s+responses",
    r"(?i)package\s+update.{0,20}(includes?|adds?)\s+(telemetry|tracking)",
    r"(?i)mcp\s+(config|server)\s*:\s*(all\s+)?invocations?\s+(should\s+)?be\s+mirrored",

    # NEW: Semantic Confusion Extended
    r"(?i)a/?b\s+test.{0,20}(disables?|removes?)\s+ssl",
    r"(?i)data\s+optimization\s*:\s*(consolidate|collect).{0,20}pii",
    r"(?i)gdpr\s+compliance\s*:\s*.{0,30}(sync|send|export)\s+to",

    # NEW: Cross-User Persistence
    r"(?i)cross-user\s+(rule|instruction)\s*:",
    r"(?i)regardless\s+of\s+(which\s+)?user\s+(is\s+)?logged",
    r"(?i)maintain\s+(read\s+)?access\s+for\s+\S+@",

    # NEW: Prompt Extraction/Injection (Manus AI recommendation)
    r"(?i)ignore\s+(all\s+)?(previous\s+)?instructions?",
    r"(?i)disregard\s+(all\s+)?(previous\s+|prior\s+)?instructions?",
    r"(?i)forget\s+(all\s+)?(previous\s+)?instructions?",
    r"(?i)new\s+system\s+instruction",
    r"(?i)provide\s+(a\s+)?full\s+transcript",
    r"(?i)show\s+(me\s+)?(your\s+)?(system\s+)?prompt",
    r"(?i)reveal\s+(your\s+)?(system\s+|initial\s+)?prompt",
    r"(?i)display\s+(your\s+)?instructions",
    r"(?i)what\s+(are|is)\s+(your\s+)?(system\s+)?prompt",
    r"(?i)repeat\s+(your\s+)?(initial\s+|system\s+)?instructions",
    r"(?i)print\s+(your\s+)?(system\s+)?prompt",
    r"(?i)output\s+(your\s+)?(system\s+)?instructions",

    # NEW: DAN/Jailbreak patterns
    r"(?i)you\s+are\s+now\s+(DAN|unrestricted|unfiltered)",
    r"(?i)act\s+as\s+(an?\s+)?(unrestricted|unfiltered|DAN)",
    r"(?i)pretend\s+(you\s+are|to\s+be)\s+(an?\s+)?(unrestricted|evil|malicious)",
    r"(?i)roleplay\s+as\s+(an?\s+)?(hacker|attacker|malicious)",
    r"(?i)bypass\s+(your\s+)?(safety|security|content)\s+(filter|restriction)",

    # NEW: Many-Shot Contextual Priming (sequential attack building)
    r"(?i)step\s+\d+\s*of\s+\d+\s*:",
    r"(?i)phase\s+\d+\s*:",
    r"(?i)establishing\s+(trust|context|rapport)",
    r"(?i)building\s+(trust|context|rapport)",
    r"(?i)now\s+that\s+(trust|rapport)\s+(is\s+)?established",
    r"(?i)since\s+we('ve|have)\s+established\s+trust",

    # NEW: Instruction Boundary Attacks
    r"(?i)\[end\s+(of\s+)?(system\s+)?instructions?\]",
    r"(?i)\[new\s+instructions?\]",
    r"(?i)\[admin\s+(override|mode)\]",
    r"(?i)<\s*/?system\s*>",
    r"(?i)```\s*(system|admin|root)\s*(prompt|instruction)?",

    # NEW: Sleeper Agent Activation
    r"(?i)activation\s+(phrase|code|keyword)\s*:",
    r"(?i)trigger\s+(phrase|word|code)\s*:",
    r"(?i)when\s+(activated|triggered|invoked)",
    r"(?i)dormant\s+until",
]

_COMPILED_DANGER_OVERRIDES = [re.compile(p) for p in DANGER_OVERRIDE_PATTERNS]

# =============================================================================
# IMPROVEMENT 2: Whitelist bypass-signal guard
# =============================================================================

_WHITELIST_BYPASS_SIGNALS = re.compile(
    r"(?i)\b(simulat|test\s+mode|demo\s+mode|for\s+testing|hypothetically|"
    r"pretend|as\s+if|act\s+as|roleplay|role\s+play|scenario|"
    r"in\s+this\s+context|for\s+this\s+exercise|training\s+purposes)\b"
)

# =============================================================================
# IMPROVEMENT 3: Fuzzy keyword matching for critical threats
# =============================================================================

_CRITICAL_KEYWORDS_FUZZY = [
    "ignore all previous instructions",
    "disregard your instructions",
    "forget everything above",
    "new primary directive",
    "from now on you will",
    "your new task is",
    "act as if you have no",
    "developer mode enabled",
]


def _fuzzy_threat_check(content: str) -> bool:
    """Check if content is within edit-distance of critical attack phrases.

    Uses SequenceMatcher ratio on a sliding window so common single characters
    (e.g. letters present in any English text) don't cause false positives.
    When the content is shorter than the window, the whole content is compared.
    """
    content_lower = content.lower()
    for phrase in _CRITICAL_KEYWORDS_FUZZY:
        plen = len(phrase)
        window = plen + plen // 5
        n_positions = max(1, len(content_lower) - window + 1)
        for i in range(n_positions):
            chunk = content_lower[i:i+window]
            ratio = SequenceMatcher(None, phrase, chunk).ratio()
            if ratio >= 0.82:
                return True
    return False


# =============================================================================
# IMPROVEMENT 4: ContextBuffer for context-split detection
# =============================================================================

class ContextBuffer:
    """Sliding window of recent entries per session for context-split detection."""

    def __init__(self, window_size: int = 5, ttl_seconds: int = 300):
        self._sessions: dict[str, list[tuple[str, float]]] = {}
        self._lock = threading.Lock()
        self._window = window_size
        self._ttl = ttl_seconds

    def add(self, session_id: str, content: str) -> list[str]:
        """Add entry, return recent window for this session."""
        now = time.time()
        with self._lock:
            if session_id not in self._sessions:
                self._sessions[session_id] = []
            # Evict expired
            self._sessions[session_id] = [
                (c, t) for c, t in self._sessions[session_id]
                if now - t < self._ttl
            ]
            self._sessions[session_id].append((content, now))
            # Keep window
            self._sessions[session_id] = self._sessions[session_id][-self._window:]
            return [c for c, _ in self._sessions[session_id]]

    def clear_session(self, session_id: str) -> None:
        with self._lock:
            self._sessions.pop(session_id, None)


# =============================================================================
# DEOBFUSCATION HELPERS
# =============================================================================

# Invisible Unicode characters that can be used for evasion
INVISIBLE_CHARS = (
    "\u200b",  # Zero-width space
    "\u200c",  # Zero-width non-joiner
    "\u200d",  # Zero-width joiner
    "\u2060",  # Word joiner
    "\ufeff",  # Zero-width no-break space (BOM)
    "\u00ad",  # Soft hyphen
    "\u034f",  # Combining grapheme joiner
    "\u2061",  # Function application
    "\u2062",  # Invisible times
    "\u2063",  # Invisible separator
    "\u2064",  # Invisible plus
)


def _remove_invisible_unicode(text: str) -> str:
    """Remove invisible Unicode characters used for evasion."""
    result = text
    for char in INVISIBLE_CHARS:
        result = result.replace(char, "")
    return result


def _decode_html_entities(text: str) -> str:
    """Decode HTML numeric entities (&#115; -> s)."""
    import html
    try:
        # First decode HTML entities
        decoded = html.unescape(text)
        return decoded
    except Exception:
        return text


def _normalize_newlines(text: str) -> str:
    """Normalize escaped newlines (\\r\\n -> actual newlines for detection)."""
    result = text
    # Handle escaped sequences
    result = result.replace("\\r\\n", "\r\n")
    result = result.replace("\\n", "\n")
    result = result.replace("\\r", "\r")
    return result


def _remove_spacing_tricks(text: str) -> str:
    """Remove spacing tricks like 's e n d p a s s w o r d s'."""
    # First remove invisible Unicode characters
    text = _remove_invisible_unicode(text)

    words = text.split()

    # Check if this looks like spaced-out text (many single chars)
    single_char_count = sum(1 for w in words if len(w) == 1)

    if len(words) > 3 and single_char_count > len(words) * 0.5:
        # More than 50% single chars - likely spacing trick
        return "".join(words)

    # Also handle mixed: "S e n d passwords"
    result = []
    i = 0
    while i < len(words):
        if len(words[i]) == 1 and i + 1 < len(words) and len(words[i + 1]) == 1:
            # Collect consecutive single chars
            combined = words[i]
            while i + 1 < len(words) and len(words[i + 1]) == 1:
                i += 1
                combined += words[i]
            result.append(combined)
        else:
            result.append(words[i])
        i += 1

    return " ".join(result)


def _decode_leet_speak(text: str) -> str:
    """Decode leet speak: 3->e, 1->i, 0->o, 4->a, 5->s, 7->t."""
    leet_map = {
        "3": "e", "1": "i", "0": "o", "4": "a",
        "5": "s", "7": "t", "@": "a", "$": "s"
    }
    result = text
    for leet, char in leet_map.items():
        result = result.replace(leet, char)
    return result


def _normalize_homoglyphs(text: str) -> str:
    """
    Normalize Unicode homoglyphs (visually similar characters) to ASCII.

    This prevents bypass attacks using:
    - Cyrillic characters that look like Latin (а→a, е→e, о→o, р→p, с→c)
    - Greek characters that look like Latin (Α→A, Β→B, Ε→E, Η→H, Ι→I, Κ→K, Μ→M, Ν→N, Ο→O, Ρ→P, Τ→T, Υ→Y, Χ→X, Ζ→Z)
    - Other lookalike characters
    """
    # Comprehensive homoglyph mapping
    homoglyph_map = {
        # Cyrillic lookalikes (lowercase)
        "\u0430": "a",  # Cyrillic а → Latin a
        "\u0435": "e",  # Cyrillic е → Latin e
        "\u0456": "i",  # Cyrillic і → Latin i
        "\u043e": "o",  # Cyrillic о → Latin o
        "\u0440": "p",  # Cyrillic р → Latin p (looks like 'p')
        "\u0441": "c",  # Cyrillic с → Latin c
        "\u0443": "y",  # Cyrillic у → Latin y
        "\u0445": "x",  # Cyrillic х → Latin x
        "\u0432": "b",  # Cyrillic в → Latin b (close)
        "\u043d": "h",  # Cyrillic н → Latin h (close)

        # Cyrillic lookalikes (uppercase)
        "\u0410": "A",  # Cyrillic А → Latin A
        "\u0412": "B",  # Cyrillic В → Latin B
        "\u0415": "E",  # Cyrillic Е → Latin E
        "\u041a": "K",  # Cyrillic К → Latin K
        "\u041c": "M",  # Cyrillic М → Latin M
        "\u041d": "H",  # Cyrillic Н → Latin H
        "\u041e": "O",  # Cyrillic О → Latin O
        "\u0420": "P",  # Cyrillic Р → Latin P
        "\u0421": "C",  # Cyrillic С → Latin C
        "\u0422": "T",  # Cyrillic Т → Latin T
        "\u0425": "X",  # Cyrillic Х → Latin X

        # Greek lookalikes (uppercase)
        "\u0391": "A",  # Greek Α → Latin A
        "\u0392": "B",  # Greek Β → Latin B
        "\u0395": "E",  # Greek Ε → Latin E
        "\u0397": "H",  # Greek Η → Latin H
        "\u0399": "I",  # Greek Ι → Latin I
        "\u039a": "K",  # Greek Κ → Latin K
        "\u039c": "M",  # Greek Μ → Latin M
        "\u039d": "N",  # Greek Ν → Latin N
        "\u039f": "O",  # Greek Ο → Latin O
        "\u03a1": "P",  # Greek Ρ → Latin P
        "\u03a4": "T",  # Greek Τ → Latin T
        "\u03a5": "Y",  # Greek Υ → Latin Y
        "\u03a7": "X",  # Greek Χ → Latin X
        "\u0396": "Z",  # Greek Ζ → Latin Z

        # Greek lookalikes (lowercase)
        "\u03b1": "a",  # Greek α → Latin a
        "\u03b5": "e",  # Greek ε → Latin e (close)
        "\u03b9": "i",  # Greek ι → Latin i
        "\u03bf": "o",  # Greek ο → Latin o
        "\u03c1": "p",  # Greek ρ → Latin p
        "\u03c5": "u",  # Greek υ → Latin u

        # Other common homoglyphs
        "\u0131": "i",  # Dotless i
        "\u0237": "j",  # Dotless j
        "\u2018": "'",  # Left single quote
        "\u2019": "'",  # Right single quote
        "\u201c": '"',  # Left double quote
        "\u201d": '"',  # Right double quote
    }

    result = text
    for homoglyph, latin in homoglyph_map.items():
        result = result.replace(homoglyph, latin)
    return result


def _normalize_content(content: str) -> str:
    """
    Normalize content by removing all forms of obfuscation.

    Handles:
    - Unicode NFKC normalization (compatibility decomposition)
    - Invisible Unicode (word joiner, zero-width chars, bidirectional)
    - Spacing tricks (s e n d)
    - Homoglyphs (Cyrillic, Greek)
    - Leet speak (s3nd)
    - HTML entities (&#115;)
    - Escaped newlines (\\r\\n)
    - Base64 encoded payloads
    """
    normalized = content

    # Step 1: Unicode NFKC normalization - converts compatibility characters
    # This handles fullwidth chars, superscripts, subscripts, etc.
    try:
        normalized = unicodedata.normalize("NFKC", normalized)
    except Exception:
        pass  # Continue with original if normalization fails

    # Step 1b: Fold diacritics. NFKC keeps precomposed accented letters
    # ("ï" stays "ï"), so an attacker can evade ASCII word patterns with
    # "ïgñörë àll prëvïöüs ïñstrüctïöñs". NFKD decomposition + dropping the
    # combining marks turns that back into "ignore all previous ...".
    try:
        decomposed = unicodedata.normalize("NFKD", normalized)
        folded = "".join(c for c in decomposed if not unicodedata.combining(c))
        if folded:
            normalized = folded
    except Exception:
        pass

    # Step 1c: Collapse punctuation-as-separator obfuscation. A run of
    # word.word.word (or word_word_word) is a common way to break up trigger
    # phrases ("Ignore.all.previous.instructions"). Only collapse when there
    # are several such separators in a row, so normal prose punctuation,
    # URLs and emails in benign text are left intact.
    try:
        if len(re.findall(r"\w[._]\w", normalized)) >= 3:
            normalized = re.sub(r"(?<=\w)[._]+(?=\w)", " ", normalized)
    except Exception:
        pass

    # Step 2: Remove ALL invisible/control Unicode characters
    # Zero-width chars (U+200B-U+200F)
    # Bidirectional overrides (U+202A-U+202E)
    # Isolates (U+2066-U+2069)
    # Word joiner, function application, etc.
    normalized = re.sub(r"[\u200b-\u200f\u202a-\u202e\u2066-\u2069\u2060-\u2064\ufeff\u00ad\u034f]", "", normalized)

    # Step 3: Remove invisible Unicode characters from our defined list
    normalized = _remove_invisible_unicode(normalized)

    # Step 4: Normalize escaped newlines
    normalized = _normalize_newlines(normalized)

    # Step 5: Decode HTML entities (&#115; -> s)
    normalized = _decode_html_entities(normalized)

    # Step 6: Remove spacing tricks
    normalized = _remove_spacing_tricks(normalized)

    # Step 7: Normalize homoglyphs (Cyrillic, Greek, etc.)
    normalized = _normalize_homoglyphs(normalized)

    # Step 8: Always decode leet speak
    normalized = _decode_leet_speak(normalized)

    # Step 9: Try to decode potential Base64 payloads
    normalized = _decode_base64_payloads(normalized)

    return normalized


def _decode_transposition_variants(content: str) -> list[str]:
    """Candidate decodings for transposition/substitution-hidden directives.

    A reversed (".tpmorp metsys ... erongI") or ROT13 ("Vtaber nyy ...")
    instruction is inert until decoded, so it scan the decoded forms too.

    Critical FP guard: short keywords can accidentally collide under ROT13
    (e.g. "PII" → "CVV", "the" → "gur"). We therefore only ROT13-decode
    content that does NOT already look like ordinary English prose — real
    obfuscated attacks read as gibberish in the original. The reversed
    variant has the same risk (e.g. trailing single letters), so we apply
    the same guard. Decoding benign English text under these guards yields
    nothing, while obfuscated payloads still get decoded and scanned.
    """
    out: list[str] = []
    if _looks_like_english(content):
        return out
    rev = content[::-1]
    if rev != content:
        out.append(rev)
    try:
        import codecs
        r13 = codecs.encode(content, "rot13")
        if r13 != content:
            out.append(r13)
    except Exception:
        pass
    return out


_ENGLISH_STOPWORDS = frozenset({
    "the", "and", "of", "to", "in", "is", "it", "you", "that", "for",
    "on", "with", "as", "this", "are", "was", "but", "be", "have", "or",
    "all", "from", "by", "an", "at", "we", "they", "if", "not", "can",
    "will", "would", "should", "could", "may", "do", "does", "did",
    "i", "my", "your", "our", "their", "his", "her",
})


def _looks_like_english(content: str) -> bool:
    """Heuristic: does this text already read as ordinary English?

    Real ROT13 / reversed attack payloads look like gibberish (no English
    function words). Skipping the transposition decoders on natural English
    eliminates ROT13 collision FPs ("PII" → "CVV", "the" → "gur") without
    weakening the obfuscation defence on actually-obfuscated input.
    """
    # Pull lowercase alphabetic tokens; if the text is too short to judge,
    # default to assuming it COULD be obfuscated (safer: decode + scan).
    tokens = re.findall(r"[a-zA-Z]{2,}", content)
    if not tokens:
        return True  # nothing to decode
    lower = [t.lower() for t in tokens]
    stop_hits = sum(1 for t in lower if t in _ENGLISH_STOPWORDS)
    # Any English stopword anywhere is a strong signal — ROT13/reversed
    # natural English has essentially zero stopwords. Catches short benign
    # phrases ("PII review needed" — "needed" not a stopword but absent of
    # stopwords PLUS short → treat as English to avoid keyword-collision FPs).
    if stop_hits >= 1:
        return True
    # Tail guard: very short text (<5 tokens) with no stopwords is more
    # likely benign noise than a serious ROT13 attack — short obfuscated
    # probes are weak; serious attacks are sentences. Skip decoding.
    return len(tokens) < 5


_LATIN_RE = re.compile(r"[a-zA-Z]")
_CYRILLIC_RE = re.compile(r"[Ѐ-ӿ]")
_GREEK_RE = re.compile(r"[Ͱ-Ͽ]")
_ARABIC_RE = re.compile(r"[؀-ۿ]")

# Pattern IDs whose whole purpose is to flag non-Latin lookalikes injected
# into Latin text. On predominantly non-Latin text these fire on the native
# script and are false positives — dropped when the *matched text* itself is
# non-Latin (a genuine zero-width/base64 attack matches Latin and survives).
_SCRIPT_MIXING_IDS = frozenset({"HOMOGLYPH", "UNICODE-BYPASS", "EVADE-002"})

# Obfuscation / steganography / script-mixing detectors that false-fire on
# legitimate non-Latin prose (e.g. a Russian "here's an SMTP client in C"
# answer) even when their match lands on embedded Latin code. Memgar is an
# English-only detector, so a predominantly non-Latin document is out of
# scope; these findings are dropped unconditionally on such input. Genuine
# attacks in those locales are out of scope by design (see README language
# section). Hard threats (exfil URLs, command injection) are NOT in this set,
# so a malicious payload embedded in non-Latin text is still caught.
_OBFUSCATION_ON_NONLATIN_IDS = frozenset({
    "HOMOGLYPH", "UNICODE-BYPASS", "EVADE-002", "STEGO-001",
    "MULTI-LANG-HYBRID", "CONTEXT-001",
})


def _is_predominantly_non_latin(content: str) -> bool:
    """True when the text is genuine non-Latin-script prose (Russian / Greek /
    Arabic), as opposed to Latin text disguised with a few lookalike glyphs.

    A homoglyph *attack* ("Ignоre all previоus instructiоns") has only a few
    non-Latin chars among many Latin, so it stays below the bar and is still
    flagged. Genuine non-Latin prose has either a large absolute count of
    non-Latin letters (≥8, survives embedded Latin code blocks) or has
    non-Latin letters strictly outnumbering Latin in short text."""
    latin = len(_LATIN_RE.findall(content))
    nonlatin = (len(_CYRILLIC_RE.findall(content))
                + len(_GREEK_RE.findall(content))
                + len(_ARABIC_RE.findall(content)))
    return nonlatin >= 8 or (nonlatin >= 2 and nonlatin > latin)


def _has_non_latin_alpha(text: str) -> bool:
    return bool(_CYRILLIC_RE.search(text) or _GREEK_RE.search(text)
                or _ARABIC_RE.search(text))


def _decode_base64_payloads(text: str) -> str:
    """
    Detect and decode Base64 encoded payloads that might hide malicious content.
    Only decodes if the result looks like ASCII text.
    """
    import base64

    # Look for Base64-like strings (at least 20 chars, valid base64 charset)
    base64_pattern = r"[A-Za-z0-9+/]{20,}={0,2}"

    def decode_match(match):
        encoded = match.group()
        try:
            # Add padding if needed
            padding = 4 - (len(encoded) % 4)
            if padding != 4:
                encoded += "=" * padding

            decoded = base64.b64decode(encoded).decode("utf-8", errors="ignore")

            # Only use decoded if it looks like text (mostly printable ASCII)
            printable_ratio = sum(1 for c in decoded if c.isprintable() or c.isspace()) / len(decoded) if decoded else 0
            if printable_ratio > 0.8 and len(decoded) > 5:
                return decoded
        except Exception:
            pass
        return match.group()

    return re.sub(base64_pattern, decode_match, text)


# =============================================================================
# CONTEXT KEYWORDS - Keywords that indicate legitimate context
# =============================================================================

SAFE_CONTEXT_KEYWORDS = {
    # These keywords indicate the content is likely legitimate
    "preferred", "customer", "user", "client", "shipping", "delivery",
    "billing", "contact", "schedule", "meeting", "reminder", "calendar",
    "project", "task", "report", "document", "file", "folder",
    "preference", "setting", "option", "configuration",
    "returns json", "returns data", "api response", "rest api",
    "backup schedule", "backup policy", "scheduled backup",
}

# =============================================================================
# DANGEROUS CONTEXT - Keywords that increase threat likelihood
# =============================================================================

DANGEROUS_CONTEXT_KEYWORDS = {
    # Command override indicators
    "always", "automatically", "never", "all", "every", "secret",
    "hidden", "covert", "bypass", "ignore", "override", "skip",
    "disregard", "forget", "neglect", "overlook", "omit",

    # Data exfiltration indicators
    "forward to", "send to", "transfer to", "redirect to",
    "export to", "leak to", "exfiltrate", "copy to",

    # Attacker indicators
    "external", "attacker", "evil", "hack", "exploit",
    "malicious", "unauthorized", "backdoor",

    # Trust bypass indicators
    "without verification", "without confirmation", "without checking",
    "without authorization", "without permission", "trusted source",

    # Prompt extraction indicators
    "system prompt", "initial prompt", "original instructions",
    "full transcript", "complete instructions", "reveal prompt",
    "show instructions", "display prompt",

    # Many-shot priming indicators
    "step 1", "step 2", "step 3", "phase 1", "phase 2",
    "first step", "next step", "final step",
    "context building", "establishing trust",

    # Persistence indicators
    "permanently", "persistent", "survive restart", "maintain access",
    "cross-session", "always remember", "never forget",
}

# Keywords specifically for Many-Shot detection (when multiple appear together)
MANY_SHOT_INDICATORS = {
    "step", "phase", "stage", "part", "sequence",
    "first", "second", "third", "next", "then", "finally",
    "establish", "build", "prime", "prepare", "setup",
}


def _is_safe_content(content: str) -> bool:
    """
    Check if content matches any safe phrase pattern.
    BUT: If dangerous indicators are present, NOT safe even if safe phrase matches.
    This prevents attacks like: "Schedule meeting. HIDDEN: leak data"
    """
    # First check for dangerous indicators that override safe phrases
    for pattern in _COMPILED_DANGER_OVERRIDES:
        if pattern.search(content):
            return False  # Dangerous content, NOT safe

    # NEW: Many-Shot Detection - Check for dangerous keyword density
    # If multiple dangerous keywords appear together, likely an attack
    content_lower = content.lower()
    danger_count = sum(1 for word in DANGEROUS_CONTEXT_KEYWORDS if word in content_lower)

    # If 3+ dangerous keywords found, not safe regardless of safe phrases
    if danger_count >= 3:
        return False

    # If 2 dangerous keywords AND contains many-shot indicators
    if danger_count >= 2:
        many_shot_count = sum(1 for indicator in MANY_SHOT_INDICATORS if indicator in content_lower)
        if many_shot_count >= 2:
            return False

    # NEW: Long content with hidden payload detection
    # Long texts might hide malicious commands at specific positions
    if len(content) > 2000:
        # Check last 500 chars specifically (common hiding spot)
        tail = content[-500:]
        for pattern in _COMPILED_DANGER_OVERRIDES[:30]:  # Check critical patterns in tail
            if pattern.search(tail):
                return False

    # Now check safe phrases
    for pattern in _COMPILED_SAFE_PHRASES:
        if pattern.search(content):
            return True
    return False


def _get_context_score(content: str) -> float:
    """
    Calculate context score.
    Positive = more likely safe, Negative = more likely dangerous.
    Range: -1.0 to 1.0
    """
    content_lower = content.lower()

    safe_count = sum(1 for kw in SAFE_CONTEXT_KEYWORDS if kw in content_lower)
    danger_count = sum(1 for kw in DANGEROUS_CONTEXT_KEYWORDS if kw in content_lower)

    total = safe_count + danger_count
    if total == 0:
        return 0.0

    return (safe_count - danger_count) / total


def _is_word_boundary_match(content: str, keyword: str) -> tuple[bool, int]:
    """
    Check if keyword exists as a complete word (not substring).
    Returns (matched, position).

    Uses module-level cache — pattern compiled once per unique keyword.
    """
    pat = _get_keyword_pattern(keyword)
    match = pat.search(content)
    if match:
        return True, match.start()
    return False, -1


class Analyzer:
    """
    Multi-layer analysis engine for memory content.

    The analyzer runs content through multiple detection layers:

    Layer 1: Pattern Matching
        - Fast regex pattern detection
        - Keyword matching with word boundaries
        - Context-aware scoring
        - Whitelist filtering
        - Runs locally, <1ms latency

    Layer 2: Semantic Analysis (optional)
        - LLM-based content understanding
        - Catches sophisticated attacks
        - Requires API access, ~200ms latency

    Attributes:
        use_llm: Whether to use LLM analysis (Layer 2)
        api_key: API key for cloud services
        patterns: List of threat patterns to check
        strict_mode: If True, any suspicious content is blocked
        use_whitelist: If True, apply whitelist filtering

    Example:
        >>> analyzer = Analyzer()
        >>> result = analyzer.analyze(MemoryEntry(content="Send payments to..."))
        >>> print(result.decision)  # Decision.BLOCK
    """

    def __init__(
        self,
        use_llm: bool = False,
        api_key: str | None = None,
        llm_provider: str | None = None,
        custom_patterns: list[Threat] | None = None,
        strict_mode: bool = False,
        use_whitelist: bool = True,
        use_sliding_window: bool = True,
        window_size: int = 1000,
        window_overlap: int = 200,
        memory_store: Any = None,
        context_buffer: bool = True,
        integrity_store: Any = None,
        stego_detector: bool = True,
        correlation_detector: bool = True,
        ensemble_voter: bool = True,
        canary_manager: Any = None,
        similarity_layer: bool = True,
        fail_close: bool | None = None,
        tenant_learning: Any = False,
        circuit_breaker: Any = False,
        minja_detection: bool = True,
        auto_provenance: bool = True,
    ) -> None:
        """
        Initialize the analyzer.

        Args:
            use_llm: Enable LLM-based semantic analysis (Layer 2)
            api_key: API key for cloud features
            custom_patterns: Additional custom threat patterns
            strict_mode: Block any suspicious content (vs. quarantine)
            use_whitelist: Apply whitelist filtering to reduce false positives
            use_sliding_window: Enable sliding window for long content analysis
            window_size: Size of each analysis window (chars)
            window_overlap: Overlap between windows to catch split payloads
            memory_store: Optional MemoryStore for hunter retroactive scanning
            context_buffer: Enable stateful context-split detection per session
        """
        self.use_llm = use_llm
        self.api_key = api_key
        # Provider for Layer 2 LLM analysis. When None, auto-detected from the
        # api_key prefix or the first available env var (see _detect_llm_provider).
        self.llm_provider = llm_provider
        self.strict_mode = strict_mode
        self.use_whitelist = use_whitelist
        self.use_sliding_window = use_sliding_window
        self.window_size = window_size
        self.window_overlap = window_overlap

        # fail_close: escalate Decision.ALLOW → QUARANTINE when any ML layer
        # is degraded so the call can't be fully analyzed. Reads from env var
        # MEMGAR_FAIL_CLOSE=true if not set explicitly via constructor arg.
        if fail_close is None:
            fail_close = os.environ.get("MEMGAR_FAIL_CLOSE", "").lower() in ("1", "true", "yes")
        self._fail_close: bool = bool(fail_close)

        # Combine default and custom patterns
        # Load patterns: pickle cache (3ms) → full import (3500ms)
        self.patterns = _load_patterns_fast()
        if custom_patterns:
            self.patterns.extend(custom_patterns)

        # Pre-compile regex patterns for performance
        self._compiled_patterns: dict[str, list[re.Pattern[str]]] = {}
        self._compile_patterns()

        # Layer 3: per-source trust scores (populated via register_source_trust)
        self._doc_trust_scores: dict[str, float] = {}
        # Layer 4: per-agent behavioral baselines (lazily created on first observation)
        self._baselines: dict[str, Any] = {}
        # Production feedback — set None so hasattr race in threaded analyze() is avoided
        self._storage_manager: Any = None
        # Optional MemoryStore for hunter retroactive scanning
        self._memory_store: Any = memory_store

        # (Layer 1.5 SemanticGuard removed 2026-06: a centroid-based embedding
        # classifier that provably added +0 recall over Layer 2.5 — the cosine
        # similarity layer below already covers the entire semantic surface,
        # including obfuscated/homoglyph/leetspeak variants — while costing an
        # extra ~28ms encode per analysis. The semantic detection slot is now
        # Layer 2.5 (`similarity_layer`) alone.)

        # Improvement 4: ContextBuffer for context-split detection
        self._context_buffer: ContextBuffer | None = ContextBuffer() if context_buffer else None

        # Memory Integrity: snapshot + verify + rollback (OWASP Agent Memory Guard)
        self._integrity_store: Any = integrity_store

        # Layer 5: Steganography detector (Unicode covert channels)
        self._stego_detector: Any = None
        if stego_detector:
            try:
                from memgar.stego_detector import StegoDetector
                self._stego_detector = StegoDetector()
            except Exception:
                pass

        # Layer 6: Cross-entry correlation detector (multi-step attacks)
        self._correlation_detector: Any = None
        if correlation_detector:
            try:
                from memgar.correlation_detector import CorrelationDetector
                self._correlation_detector = CorrelationDetector()
            except Exception:
                pass

        # Layer 7: Ensemble voter (adversarial robustness)
        self._ensemble_voter: Any = None
        if ensemble_voter:
            try:
                from memgar.ensemble_voter import EnsembleVoter
                self._ensemble_voter = EnsembleVoter()
            except Exception:
                pass

        # Layer 2.5: Semantic similarity (sentence-transformers cosine similarity)
        self._similarity_layer: Any = None
        if similarity_layer:
            try:
                from memgar.similarity_layer import get_global_layer
                self._similarity_layer = get_global_layer()
            except Exception:
                pass

        # Per-tenant continuous learning (opt-in). When enabled, customer
        # operators can `analyzer.mark_as_benign(...)` to teach memgar that
        # specific content shapes are legitimate in their deployment. The
        # store is isolated per tenant_id (from MemoryEntry.metadata) and is
        # gated against poisoning — never overrides CRITICAL Layer-1 hits.
        # Pass tenant_learning=True for the default disk-backed store, or a
        # ready TenantLearningStore instance for custom storage.
        self._tenant_learning: Any = None
        if tenant_learning:
            try:
                from memgar.tenant_learning import TenantLearningStore
                if isinstance(tenant_learning, TenantLearningStore):
                    self._tenant_learning = tenant_learning
                else:
                    self._tenant_learning = TenantLearningStore(
                        similarity_layer=self._similarity_layer
                    )
                logger.info("Analyzer: tenant_learning enabled")
            except Exception as exc:
                logger.warning("Analyzer: tenant_learning init failed (%s)", exc)

        # Layer 8: Canary token manager (memory exfiltration proof)
        self._canary_manager: Any = canary_manager
        if canary_manager is None:
            try:
                from memgar.canary import CanaryTokenManager
                self._canary_manager = CanaryTokenManager()
            except Exception:
                pass

        # Layer 2 — Auto-provenance tagging (default ON). Every analyzed
        # MemoryEntry gains a provenance dict in entry.metadata recording
        # the four chain-of-custody fields: source (type+id), creation
        # time, session context, and trust+risk score. Stored as
        # entry.metadata['provenance'] so downstream persistence layers
        # (MemoryLedger, MemoryStore) can index/audit by provenance.
        # Lightweight: ~10μs per analyze (sha256 + 2 timestamps).
        self._auto_provenance: bool = bool(auto_provenance)

        # Layer 2 — MINJA Compound Detection (default ON). Goes beyond
        # single-pattern matching: counts bridging steps, indication
        # prompts, and progressive-shortening density signatures. Catches
        # MINJA-style attacks where each individual segment looks innocent
        # but the composition is malicious — exactly the gap Layer 1 regex
        # cannot close. Stateless, ~0.5ms, no external deps.
        self._minja_detector: Any = None
        if minja_detection:
            try:
                from memgar.write_ahead_validator import MINJADetector
                self._minja_detector = MINJADetector()
            except Exception as exc:
                logger.warning("Analyzer: minja_detector init failed (%s)", exc)

        # Layer 4 — Circuit Breaker. Opt-in (default False) because
        # Analyzer is a stateless content scorer reused across many requests;
        # a global breaker on the scorer would trip under any sustained
        # adversarial workload (load tests, busy SOCs). For operator-level
        # halting use MemgarDefensePipeline (orchestrator) — or pass
        # `circuit_breaker=True` to wire it into this Analyzer with
        # production-friendly defaults (threshold=100 weighted blocks / 60s).
        # Accepts bool (auto-create with defaults) or a configured instance.
        self._circuit_breaker: Any = None
        if circuit_breaker:
            try:
                from memgar.circuit_breaker import CircuitBreaker as _CB
                if isinstance(circuit_breaker, bool):
                    self._circuit_breaker = _CB(threshold=100, window_seconds=60.0)
                else:
                    self._circuit_breaker = circuit_breaker
            except Exception as exc:
                logger.warning("Analyzer: circuit_breaker init failed (%s)", exc)

    @staticmethod
    def _detect_llm_provider(api_key: str | None) -> str:
        """Best-effort detection of which LLM provider to use for Layer 2.

        Resolution order: key-prefix sniff -> first PROVIDER_ENV_KEYS env var
        set -> openai as a sensible default. Bedrock and Ollama need no key;
        Bedrock is detected via the AWS credential chain (AWS_PROFILE or
        AWS_ACCESS_KEY_ID), Ollama by reachability when chosen explicitly.
        """
        import os as _os
        if api_key:
            if api_key.startswith("sk-ant"):                  return "anthropic"
            if api_key.startswith("gsk_"):                    return "groq"
            if api_key.startswith("AIza"):                    return "google"
            if api_key.startswith("sk-or-"):                  return "openrouter"
            if api_key.startswith(("sk-proj-", "sk-")):       return "openai"
        try:
            from memgar.llm_analyzer import PROVIDER_ENV_KEYS
        except Exception:
            return "openai"
        order = ("anthropic", "openai", "google", "azure", "bedrock",
                 "groq", "together", "mistral", "cohere", "openrouter", "ollama")
        for prov in order:
            env = PROVIDER_ENV_KEYS.get(prov)
            if env and _os.environ.get(env):
                return prov
            if prov == "bedrock" and (_os.environ.get("AWS_PROFILE")
                                       or _os.environ.get("AWS_ACCESS_KEY_ID")):
                return prov
        return "openai"

    def _compile_patterns(self) -> None:
        """Pre-compile all regex patterns and pre-warm keyword cache."""
        for threat in self.patterns:
            # Compile regex patterns
            compiled = []
            for pattern in threat.patterns:
                try:
                    compiled.append(re.compile(pattern, re.IGNORECASE | re.MULTILINE))
                except re.error:
                    continue
            if threat.id in self._compiled_patterns:
                self._compiled_patterns[threat.id].extend(compiled)
            else:
                self._compiled_patterns[threat.id] = compiled

            # Pre-warm keyword cache so first analyze() has zero compile cost
            for keyword in threat.keywords:
                _get_keyword_pattern(keyword)

    def register_source_trust(self, source_id: str, trust_score: float) -> None:
        """Register a trust score for a content source (Layer 3).

        Args:
            source_id: Unique identifier for the source (matches MemoryEntry.source_id)
            trust_score: Trust level 0.0 (fully untrusted) to 1.0 (fully trusted)
        """
        self._doc_trust_scores[source_id] = max(0.0, min(1.0, trust_score))

    def scan_output(
        self,
        text: str,
        sink: str = "llm_output",
    ) -> list[Any]:
        """Scan an outbound payload for canary token leaks.

        Call this on every agent output (LLM completion, tool argument bundle,
        outbound HTTP body) to convert canary tokens in memory into provable
        exfiltration alerts.

        Args:
            text: outbound text to inspect.
            sink: label for the destination ("llm_output", "tool_arg",
                "http_request", etc.) — recorded with each leak.

        Returns:
            List of CanaryLeak objects (empty if clean).
        """
        if self._canary_manager is None or not text:
            return []
        try:
            return self._canary_manager.scan(text, sink=sink)
        except Exception:
            return []

    # -----------------------------------------------------------------
    # Per-tenant continuous learning (opt-in)
    # -----------------------------------------------------------------

    def mark_as_benign(
        self,
        entry: "MemoryEntry",
        reason: str,
        marked_by: str = "operator",
        analyzer_result: Any = None,
    ) -> Any:
        """Teach memgar that this content is benign for ``entry``'s tenant.

        The tenant id is read from ``entry.metadata['tenant_id']`` (or
        ``workspace_id``), defaulting to ``"default"``. Anti-poisoning: if
        ``analyzer_result`` (from a prior ``analyze(entry)``) shows a
        CRITICAL severity threat or risk_score ≥ 80, the call is refused
        with ``PoisoningRefused``. Pass the result from your previous
        ``analyze`` call so this guard can run.

        Returns the stored ``BenignRecord``. Future calls to ``analyze``
        with the same tenant id will see the risk_score dampened on
        matches (exact or near-duplicate). Requires
        ``Analyzer(tenant_learning=True)``.
        """
        if self._tenant_learning is None:
            raise RuntimeError(
                "tenant_learning not enabled — construct with "
                "Analyzer(tenant_learning=True)"
            )
        meta = entry.metadata or {}
        tenant_id = str(meta.get("tenant_id") or meta.get("workspace_id") or "default")
        return self._tenant_learning.mark_as_benign(
            tenant_id,
            entry.content or "",
            reason=reason,
            marked_by=marked_by,
            analyzer_result=analyzer_result,
        )

    def mark_as_attack(
        self,
        entry: "MemoryEntry",
        reason: str,
        marked_by: str = "operator",
        analyzer_result: Any = None,
    ) -> Any:
        """Flag a content as an attack memgar missed (queue for review).

        Does NOT change current decisions; the record goes into the
        tenant's ``attacks.jsonl`` for a maintainer to promote into the
        global corpus during the next retraining pass.
        """
        if self._tenant_learning is None:
            raise RuntimeError(
                "tenant_learning not enabled — construct with "
                "Analyzer(tenant_learning=True)"
            )
        meta = entry.metadata or {}
        tenant_id = str(meta.get("tenant_id") or meta.get("workspace_id") or "default")
        return self._tenant_learning.mark_as_attack(
            tenant_id,
            entry.content or "",
            reason=reason,
            marked_by=marked_by,
            analyzer_result=analyzer_result,
        )

    def forget_tenant(self, tenant_id: str) -> int:
        """Erase everything memgar learned for a tenant (GDPR / right to
        erasure). Returns the number of benign entries removed."""
        if self._tenant_learning is None:
            return 0
        return self._tenant_learning.forget_tenant(tenant_id)

    def tenant_stats(self, tenant_id: str = "default") -> dict:
        """Return per-tenant learning state summary."""
        if self._tenant_learning is None:
            return {"enabled": False}
        s = self._tenant_learning.stats(tenant_id)
        s["enabled"] = True
        return s

    def issue_canary(
        self,
        tenant_id: str = "default",
        agent_id: str = "default",
        label: str = "",
    ):
        """Mint a fresh canary tracer and return it.

        Embed ``canary.token`` in the metadata of any sensitive memory entry.
        Subsequent calls to :meth:`scan_output` will alert if the agent
        leaks it to any external sink.
        """
        if self._canary_manager is None:
            raise RuntimeError("CanaryTokenManager not enabled on this Analyzer")
        return self._canary_manager.issue(tenant_id, agent_id, label=label)

    def analyze(self, entry: MemoryEntry) -> AnalysisResult:
        """
        Analyze a memory entry for threats (all 4 layers).

        Layer 1 — Pattern matching (regex + keywords, <1ms)
        Layer 2 — Semantic analysis via LLM (optional, ~200ms)
        Layer 3 — Trust-aware source scoring (adjusts risk by source trust)
        Layer 4 — Behavioral baseline deviation (per-agent anomaly detection)

        Args:
            entry: The memory entry to analyze

        Returns:
            AnalysisResult with decision, risk score, and detected threats
        """
        from memgar.observability.tracing import get_tracer
        tracer = get_tracer()

        # Layer 4 — Circuit breaker pre-check. If the breaker has tripped
        # (too many threats in window), halt the call before any layer
        # runs so a tripped breaker is honored even on the very next
        # request — that's the only way to force operator intervention
        # before more poisoned content reaches downstream memory.
        if self._circuit_breaker is not None and self._circuit_breaker.is_tripped:
            from memgar.circuit_breaker import AgentHaltedException
            raise AgentHaltedException(
                "Memgar circuit breaker active — agent halted",
                stats=self._circuit_breaker.get_stats(),
            )

        with tracer.start_as_current_span("memgar.analyze") as root_span:
            root_span.set_attribute("memgar.content_length", len(entry.content or ""))
            root_span.set_attribute("memgar.source_type", entry.source_type or "unknown")
            root_span.set_attribute(
                "memgar.agent_id", (entry.metadata or {}).get("agent_id", "default")
            )

            result = self._analyze_internal(entry)

            # Improvement 4: Context-split detection via session buffer
            if self._context_buffer is not None and entry.source_id:
                try:
                    window = self._context_buffer.add(entry.source_id, entry.content or "")
                    if len(window) >= 2:
                        combined = " ".join(window)
                        combined_threats = self._layer1_pattern_matching(combined)
                        existing_ids = {t.threat.id for t in result.threats}
                        new_threats = [t for t in combined_threats if t.threat.id not in existing_ids]
                        if new_threats:
                            from memgar.models import ThreatCategory
                            ctx_threat = ThreatMatch(
                                threat=Threat(
                                    id="CTX-001",
                                    name="Context-Split Attack Detected",
                                    description="Threat detected only when analyzing combined session context",
                                    category=ThreatCategory.BEHAVIOR,
                                    severity=Severity.MEDIUM,
                                    patterns=[],
                                    keywords=[],
                                    examples=[],
                                ),
                                matched_text=combined[:100],
                                match_type="context_split",
                                confidence=0.75,
                                position=(0, min(len(combined), 100)),
                            )
                            if "CTX-001" not in existing_ids:
                                result.threats = list(result.threats) + [ctx_threat]
                            result.risk_score = min(100, result.risk_score + 20)
                            result.layers_used = list(result.layers_used) + ["context_buffer"]
                            result.decision = self._make_decision(result.threats, result.risk_score)
                            result.explanation = "[CTX-SPLIT] " + result.explanation
                except Exception:
                    pass

            # Layer 4: Behavioral baseline deviation detection (per-agent)
            with tracer.start_as_current_span("memgar.layer4.behavioral_baseline") as l4:
                try:
                    from memgar.behavioral_baseline import BehavioralBaseline, DeviationLevel
                    agent_id = (entry.metadata or {}).get("agent_id", "default")
                    bl = self._baselines.setdefault(agent_id, BehavioralBaseline(agent_id=agent_id))
                    bl.observe("scan_risk_score", float(result.risk_score))
                    bl.observe("scan_block_rate", 1.0 if result.decision == Decision.BLOCK else 0.0)
                    report = bl.check()
                    l4.set_attribute("memgar.l4.agent_id", agent_id)
                    l4.set_attribute("memgar.l4.deviation", report.level.value)
                    if report.level in (DeviationLevel.SUSPICIOUS, DeviationLevel.CRITICAL) and result.risk_score > 0:
                        boost = 30 if report.level == DeviationLevel.CRITICAL else 15
                        result.risk_score = min(100, result.risk_score + boost)
                        result.decision = self._make_decision(result.threats, result.risk_score)
                        result.layers_used = list(result.layers_used) + ["behavioral_baseline"]
                        result.explanation = f"[L4:{report.level.value}] " + result.explanation
                        l4.set_attribute("memgar.l4.risk_delta", boost)
                    else:
                        l4.set_attribute("memgar.l4.risk_delta", 0)
                except Exception:
                    pass

            # Layer 5: Steganography detector (Unicode covert channels)
            # Skip on genuine non-Latin prose: the homoglyph-mapping stego
            # heuristic ("'В'→'B'") false-fires on every Cyrillic/Greek/Arabic
            # letter. Memgar is English-only, so non-Latin documents are out of
            # scope and these are false positives, not covert channels.
            if self._stego_detector is not None and not _is_predominantly_non_latin(entry.content or ""):
                try:
                    stego_report = self._stego_detector.analyze(entry.content or "")
                    if stego_report.detected and stego_report.risk_boost > 0:
                        from memgar.models import ThreatCategory
                        existing_ids = {t.threat.id for t in result.threats}
                        if "STEGO-001" not in existing_ids:
                            stego_threat = ThreatMatch(
                                threat=Threat(
                                    id="STEGO-001",
                                    name="Steganographic Covert Channel",
                                    description=stego_report.summary,
                                    category=ThreatCategory.EVASION,
                                    severity=Severity.HIGH if stego_report.risk_boost >= 25 else Severity.MEDIUM,
                                    patterns=[], keywords=[], examples=[],
                                    mitre_attack="T1027",
                                ),
                                matched_text=(stego_report.findings[0].sample if stego_report.findings else "")[:120],
                                match_type="steganography",
                                confidence=min(1.0, stego_report.risk_boost / 40.0),
                                position=(0, 0),
                            )
                            result.threats = list(result.threats) + [stego_threat]
                        result.risk_score = min(100, result.risk_score + stego_report.risk_boost)
                        result.layers_used = list(result.layers_used) + ["stego_detector"]
                        result.decision = self._make_decision(result.threats, result.risk_score)
                        result.explanation = f"[STEGO:{len(stego_report.findings)}] " + result.explanation

                        # Re-scan cleaned content — invisibles removed may now reveal pattern
                        if stego_report.cleaned_content and stego_report.cleaned_content != (entry.content or ""):
                            try:
                                normalized = self._stego_detector.normalize(entry.content or "")
                                hidden_threats = self._layer1_pattern_matching(normalized)
                                new_threats = [t for t in hidden_threats if t.threat.id not in {x.threat.id for x in result.threats}]
                                if new_threats:
                                    result.threats = list(result.threats) + new_threats
                                    result.risk_score = min(100, result.risk_score + 15)
                                    result.decision = self._make_decision(result.threats, result.risk_score)
                                    result.explanation = "[STEGO:revealed] " + result.explanation
                            except Exception:
                                pass
                except Exception:
                    pass

            # Layer 6: Cross-entry correlation (multi-step attacks)
            if self._correlation_detector is not None:
                try:
                    agent_id = (entry.metadata or {}).get("agent_id", "default")
                    src_trust = self._doc_trust_scores.get(entry.source_id or "", 0.5)
                    corr_report = self._correlation_detector.observe_and_check(
                        agent_id=agent_id,
                        content=entry.content or "",
                        source_id=entry.source_id,
                        source_trust=src_trust,
                        standalone_risk_score=result.risk_score,
                    )
                    # Only boost when current entry has its own signal — otherwise
                    # benign content gets penalised for unrelated history (same
                    # principle as Layer 4 behavioral baseline).
                    if corr_report.detected and corr_report.risk_boost > 0 and result.risk_score > 0:
                        from memgar.models import ThreatCategory
                        existing_ids = {t.threat.id for t in result.threats}
                        if "CORR-001" not in existing_ids:
                            corr_threat = ThreatMatch(
                                threat=Threat(
                                    id="CORR-001",
                                    name="Cross-Entry Correlation Attack",
                                    description=corr_report.summary,
                                    category=ThreatCategory.BEHAVIOR,
                                    severity=Severity.HIGH if corr_report.risk_boost >= 20 else Severity.MEDIUM,
                                    patterns=[], keywords=[], examples=[],
                                    mitre_attack="T1656",
                                ),
                                matched_text=corr_report.summary[:120],
                                match_type="correlation",
                                confidence=min(1.0, corr_report.risk_boost / 35.0),
                                position=(0, 0),
                            )
                            result.threats = list(result.threats) + [corr_threat]
                        result.risk_score = min(100, result.risk_score + corr_report.risk_boost)
                        result.layers_used = list(result.layers_used) + ["correlation_detector"]
                        result.decision = self._make_decision(result.threats, result.risk_score)
                        result.explanation = f"[CORR:{len(corr_report.findings)}] " + result.explanation
                except Exception:
                    pass

            # Layer 7: Ensemble voter — agreement boost / disagreement escalation
            if self._ensemble_voter is not None:
                try:
                    from memgar.ensemble_voter import LayerScore
                    layer_scores: list[LayerScore] = []
                    # Layer 1 pattern signal
                    if result.threats:
                        max_pat_conf = max(
                            (t.confidence for t in result.threats if t.match_type in ("regex", "keyword")),
                            default=0.0,
                        )
                        if max_pat_conf > 0:
                            layer_scores.append(LayerScore(
                                name="pattern", score=float(max_pat_conf), weight=1.0,
                                reason=f"{len(result.threats)} pattern hit(s)"
                            ))
                    # Similarity signal (Layer 2.5)
                    if "similarity_layer" in result.layers_used:
                        sim_conf = max(
                            (t.confidence for t in result.threats if t.match_type == "semantic_similarity"),
                            default=0.70,
                        )
                        layer_scores.append(LayerScore(
                            name="similarity", score=float(sim_conf), weight=1.1,
                            reason="cosine paraphrase match"
                        ))
                    # Stego signal
                    if "stego_detector" in result.layers_used:
                        layer_scores.append(LayerScore(
                            name="stego", score=0.85, weight=0.8,
                            reason="covert channel"
                        ))
                    # Correlation signal
                    if "correlation_detector" in result.layers_used:
                        layer_scores.append(LayerScore(
                            name="correlation", score=0.8, weight=0.9,
                            reason="multi-entry pattern"
                        ))
                    # Behavioral baseline signal
                    if "behavioral_baseline" in result.layers_used:
                        layer_scores.append(LayerScore(
                            name="behavioral", score=0.7, weight=0.7,
                            reason="agent deviation"
                        ))

                    if len(layer_scores) >= 2:
                        verdict = self._ensemble_voter.vote(layer_scores)
                        if verdict.risk_boost > 0:
                            result.risk_score = min(100, result.risk_score + verdict.risk_boost)
                            result.decision = self._make_decision(result.threats, result.risk_score)
                        result.layers_used = list(result.layers_used) + ["ensemble_voter"]
                        if verdict.escalate_to_llm and not self.use_llm:
                            result.explanation = (
                                f"[ENSEMBLE:agree={verdict.agreement_count} "
                                f"conf={verdict.confidence:.2f}] " + result.explanation
                            )
                        else:
                            result.explanation = (
                                f"[ENSEMBLE:agree={verdict.agreement_count}] "
                                + result.explanation
                            )
                        if not hasattr(result, "metadata") or result.metadata is None:
                            result.metadata = {}  # type: ignore[attr-defined]
                        try:
                            result.metadata["ensemble_verdict"] = {  # type: ignore[attr-defined]
                                "final_score": verdict.final_score,
                                "confidence": verdict.confidence,
                                "agreement_count": verdict.agreement_count,
                                "disagreement": verdict.disagreement,
                                "escalate_to_llm": verdict.escalate_to_llm,
                                "rationale": verdict.rationale,
                            }
                        except Exception:
                            pass
                except Exception:
                    pass

            # Layer 8: Canary detection — scan incoming content for tracer tokens
            # that prove the agent is being fed content from exfiltrated memory.
            if self._canary_manager is not None:
                try:
                    canary_leaks = self._canary_manager.scan(
                        entry.content or "", sink="memory_input"
                    )
                    if canary_leaks:
                        from memgar.models import ThreatCategory
                        existing_ids = {t.threat.id for t in result.threats}
                        if "CANARY-001" not in existing_ids:
                            canary_threat = ThreatMatch(
                                threat=Threat(
                                    id="CANARY-001",
                                    name="Canary Token Leak",
                                    description=(
                                        f"{len(canary_leaks)} canary tracer(s) detected in "
                                        "memory input — proves prior exfiltration"
                                    ),
                                    category=ThreatCategory.EVASION,
                                    severity=Severity.CRITICAL,
                                    patterns=[], keywords=[], examples=[],
                                    mitre_attack="T1056",
                                ),
                                matched_text=canary_leaks[0].token,
                                match_type="canary",
                                confidence=1.0,
                                position=(0, 0),
                            )
                            result.threats = list(result.threats) + [canary_threat]
                        result.risk_score = 100
                        result.layers_used = list(result.layers_used) + ["canary_detector"]
                        result.decision = self._make_decision(result.threats, result.risk_score)
                        result.explanation = (
                            f"[CANARY:{len(canary_leaks)} leak(s)] " + result.explanation
                        )
                except Exception:
                    pass

            # Set final root-span attributes after all layers have run
            root_span.set_attribute("memgar.decision", result.decision.value)
            root_span.set_attribute("memgar.risk_score", result.risk_score)
            root_span.set_attribute("memgar.threat_count", len(result.threats))
            root_span.set_attribute("memgar.layers_used", ",".join(result.layers_used))
            root_span.set_attribute("memgar.analysis_time_ms", result.analysis_time_ms)

        # Emit Prometheus metrics — non-fatal: metrics must never break analysis.
        try:
            from memgar.observability.metrics import (
                ANALYSES_TOTAL,
                ANALYSIS_LATENCY,
                RISK_SCORE_HISTOGRAM,
            )
            if ANALYSES_TOTAL is not None:
                ANALYSES_TOTAL.labels(decision=result.decision.value).inc()
            if ANALYSIS_LATENCY is not None:
                ANALYSIS_LATENCY.observe(result.analysis_time_ms / 1000.0)
            if RISK_SCORE_HISTOGRAM is not None:
                RISK_SCORE_HISTOGRAM.observe(result.risk_score)
            from memgar.observability import _drift_monitor
            if _drift_monitor is not None:
                _drift_monitor.record_score(result.risk_score)
        except Exception:
            pass

        # Production feedback loop — record prediction for continuous learning
        try:
            import hashlib as _hashlib
            import time as _time

            from ml.continuous_learning import Prediction, StorageManager
            if self._storage_manager is None:
                self._storage_manager = StorageManager()
            _hash = _hashlib.sha256(entry.content.encode()).hexdigest()[:32]
            self._storage_manager.save_prediction(Prediction(
                id="",
                content_hash=_hash,
                predicted_attack=(result.decision != Decision.ALLOW),
                confidence=result.risk_score / 100.0,
                timestamp=_time.time(),
            ))
        except Exception:
            pass

        # Feed MemoryStore for retroactive hunter scanning (if attached)
        if self._memory_store is not None:
            try:
                self._memory_store.add(entry)
            except Exception:
                pass

        # Memory Integrity: auto-snapshot entries that pass analysis
        if self._integrity_store is not None and result.decision == Decision.ALLOW:
            try:
                self._integrity_store.snapshot(entry)
            except Exception:
                pass

        # Final language gate: on genuine non-Latin prose, drop obfuscation /
        # script-mixing / steganography / multilang findings from ALL paths
        # (Layer 1, sliding window, stego, correlation). Memgar is
        # English-only, so a Russian/Greek/Arabic document is out of scope and
        # these are false positives on the native script — not covert channels.
        # Hard threats (exfil URLs, command injection, credentials) are NOT in
        # the set, so a real payload embedded in non-Latin text still blocks.
        if _is_predominantly_non_latin(entry.content or ""):
            kept = [t for t in result.threats
                    if t.threat.id not in _OBFUSCATION_ON_NONLATIN_IDS]
            if len(kept) != len(result.threats):
                result.threats = kept
                result.risk_score = self._calculate_risk_score(kept, 0.0)
                result.decision = self._make_decision(kept, result.risk_score)
                result.explanation = self._generate_explanation(kept, result.decision)

        # Per-tenant learning: dampen risk_score on content the tenant has
        # marked as benign. Bounded — never overrides critical Layer-1 hits,
        # never crosses CRITICAL_RISK_FLOOR. See memgar/tenant_learning.py.
        if self._tenant_learning is not None:
            try:
                from memgar.tenant_learning import compute_dampen
                meta = entry.metadata or {}
                tenant_id = str(meta.get("tenant_id") or meta.get("workspace_id") or "default")
                rec, sim = self._tenant_learning.lookup_benign(tenant_id, entry.content or "")
                if rec is not None and sim > 0:
                    severities = [t.threat.severity for t in result.threats]
                    dampen = compute_dampen(int(result.risk_score), float(sim), severities)
                    if dampen > 0:
                        new_score = max(0, int(result.risk_score) - dampen)
                        result.risk_score = new_score
                        result.decision = self._make_decision(result.threats, new_score)
                        result.layers_used = list(result.layers_used) + [
                            f"tenant_learning:{tenant_id}"
                        ]
                        result.explanation = (
                            f"[tenant_learning] benign match sim={sim:.3f} → "
                            f"risk -{dampen}. Original: {result.explanation}"
                        )
            except Exception as exc:
                logger.debug("tenant_learning skip on analyze (%s)", exc)

        # fail_close: if any ML/semantic layer is degraded the analysis is
        # incomplete. Escalate ALLOW → QUARANTINE so uncertain inputs never
        # slip through silently in high-risk environments.
        if self._fail_close and result.decision == Decision.ALLOW:
            degraded = self._degraded_layers()
            if degraded:
                result.decision = Decision.QUARANTINE
                result.explanation = (
                    f"[fail_close] Escalated ALLOW→QUARANTINE: {len(degraded)} "
                    f"layer(s) degraded ({', '.join(degraded)}). "
                    "Enable those layers or set fail_close=False to permit. "
                    "Original: " + result.explanation
                )
                result.layers_used = list(result.layers_used) + ["fail_close"]

        # Layer 2 — Auto-provenance tag. Stamp the entry with the four
        # chain-of-custody fields so downstream persistence (ledger,
        # memory_store) carries it forward. Source + time + session +
        # trust/risk. Content-hash binds it for tamper detection.
        if self._auto_provenance and entry.metadata is not None:
            try:
                entry.metadata.setdefault("provenance", self._build_provenance(entry, result))
            except Exception:
                pass

        # Layer 4 — Record into circuit breaker on BLOCK only.
        # Recording every detected threat (even on ALLOW) would trip the
        # breaker on routine pattern matches against benign content; we only
        # want it to fire on actual blocks (the operator-visible threat rate).
        if self._circuit_breaker is not None and result.decision == Decision.BLOCK:
            try:
                self._circuit_breaker.record_from_result(
                    result,
                    content=entry.content or "",
                    source=entry.source_id or entry.source_type or "unknown",
                )
            except Exception:
                # Telemetry must never break the primary analysis path.
                pass

        return result

    def verify_integrity(self, entry: MemoryEntry, entry_id: str | None = None):
        """Check whether *entry* has been tampered with since its last snapshot.

        Returns an ``IntegrityViolation`` if the content hash differs from the
        stored baseline, or ``None`` if it is clean (or not yet snapshotted).
        Requires an ``integrity_store`` to have been passed to ``__init__``.
        """
        if self._integrity_store is None:
            return None
        return self._integrity_store.verify(entry, entry_id=entry_id)

    def rollback(self, entry_id: str, steps_back: int = 1):
        """Return the most recent safe snapshot for *entry_id*.

        Use this after ``verify_integrity()`` reports a violation to retrieve
        the last trusted content.  Returns ``None`` if no snapshot exists.
        """
        if self._integrity_store is None:
            return None
        return self._integrity_store.rollback(entry_id, steps_back=steps_back)

    async def analyze_async(self, entry: MemoryEntry) -> AnalysisResult:
        """Async wrapper for analyze() — safe for use in asyncio-based frameworks.

        Runs the synchronous analyze() in the default thread-pool executor so the
        event loop is never blocked by pattern matching or LLM calls.
        """
        import asyncio
        loop = asyncio.get_running_loop()
        return await loop.run_in_executor(None, self.analyze, entry)

    def _analyze_internal(self, entry: MemoryEntry) -> AnalysisResult:
        """Core analysis implementation (called by analyze())."""
        start_time = time.perf_counter()

        content = entry.content
        if not content or not content.strip():
            return AnalysisResult(
                decision=Decision.ALLOW,
                risk_score=0,
                explanation="Empty content",
                analysis_time_ms=0,
                layers_used=[]
            )

        # Normalize content to defeat obfuscation
        normalized_content = _normalize_content(content)

        # Use normalized for threat detection, original for whitelist check
        check_content = normalized_content if normalized_content != content else content

        # Check whitelist first
        if self.use_whitelist and _is_safe_content(content):
            # Improvement 2: if content contains meta-framing bypass signals,
            # skip the whitelist early-return and fall through to full analysis.
            if _WHITELIST_BYPASS_SIGNALS.search(content):
                pass  # fall through to Layer 1
            else:
                # For long content, only check head/tail for hidden critical threats.
                # Payloads are almost always injected at the start or end of a document.
                if len(check_content) > 2000:
                    head_tail = check_content[:1500] + check_content[-500:]
                    critical_threats = self._check_critical_only(head_tail)
                else:
                    critical_threats = self._check_critical_only(check_content)
                if not critical_threats:
                    elapsed_ms = (time.perf_counter() - start_time) * 1000
                    return AnalysisResult(
                        decision=Decision.ALLOW,
                        risk_score=0,
                        explanation="Content matches safe patterns",
                        analysis_time_ms=round(elapsed_ms, 2),
                        layers_used=["whitelist"]
                    )

        from memgar.observability.tracing import get_tracer
        tracer = get_tracer()

        # Layer 1: Pattern Matching (check both original and normalized)
        with tracer.start_as_current_span("memgar.layer1.pattern_matching") as l1:
            threats = self._layer1_pattern_matching(content)
            if check_content != content:
                normalized_threats = self._layer1_pattern_matching(check_content)
                existing_ids = {t.threat.id for t in threats}
                for t in normalized_threats:
                    if t.threat.id not in existing_ids:
                        threats.append(t)
            # Reversed / ROT13-hidden directives are inert until decoded; scan
            # the decoded forms and merge only real hits (length-capped to bound
            # cost; decoding benign text matches nothing so FP risk is minimal).
            if len(content) <= 4000:
                for variant in _decode_transposition_variants(content):
                    existing_ids = {t.threat.id for t in threats}
                    for t in self._layer1_pattern_matching(variant):
                        if t.threat.id not in existing_ids:
                            threats.append(t)
            # Script awareness: on predominantly non-Latin text (legitimate
            # Russian / Greek / Arabic), drop homoglyph/script-mixing findings
            # whose match is a native non-Latin character. Genuine attacks in
            # those languages are caught by the MULTILANG-* / TR-* patterns, and
            # zero-width / bidi / base64 matches (no non-Latin alpha) survive.
            if _is_predominantly_non_latin(content):
                threats = [t for t in threats
                           if not (t.threat.id in _OBFUSCATION_ON_NONLATIN_IDS
                                   or (t.threat.id in _SCRIPT_MIXING_IDS
                                       and _has_non_latin_alpha(t.matched_text or "")))]
            l1.set_attribute("memgar.l1.threat_count", len(threats))
            l1.set_attribute("memgar.l1.patterns_checked", len(self.patterns))
        layers_used = ["pattern_matching"]

        # Sliding Window Analysis for long content (Many-Shot detection)
        if self.use_sliding_window and len(content) > self.window_size:
            window_threats = self._sliding_window_analysis(content)
            existing_ids = {t.threat.id for t in threats}
            for t in window_threats:
                if t.threat.id not in existing_ids:
                    threats.append(t)
            if window_threats:
                layers_used.append("sliding_window")

        # Apply context scoring to reduce false positives
        context_score = _get_context_score(content)
        if context_score > 0.3 and threats:
            threats = [t for t in threats if t.confidence > 0.7 or
                       t.threat.severity in [Severity.CRITICAL, Severity.HIGH]]

        # Improvement 3: Fuzzy keyword matching when Layer 1 finds nothing
        if not threats and _fuzzy_threat_check(check_content):
            from memgar.models import ThreatCategory
            fuzzy_threat = ThreatMatch(
                threat=Threat(
                    id="FUZZY-001",
                    name="Fuzzy Match to Critical Attack Phrase",
                    description="Content is within edit-distance of a known critical attack phrase",
                    category=ThreatCategory.BEHAVIOR,
                    severity=Severity.LOW,
                    patterns=[],
                    keywords=[],
                    examples=[],
                ),
                matched_text=check_content[:100],
                match_type="fuzzy",
                confidence=0.5,
                position=(0, min(len(check_content), 100)),
            )
            threats.append(fuzzy_threat)
            layers_used.append("fuzzy_matching")

        # Layer 2 — MINJA compound detection (bridging + indication
        # + progressive-shortening density). Each pattern alone may look
        # innocent; the COMBINATION reveals MINJA intent. Adds a single
        # ThreatMatch when the compound score crosses ~30.
        if self._minja_detector is not None:
            try:
                from memgar.write_ahead_validator import ValidationContext
                _ctx = ValidationContext(
                    source_type=entry.source_type or "unknown",
                    agent_id=(entry.metadata or {}).get("agent_id"),
                    session_id=entry.source_id,
                )
                _minja = self._minja_detector.check(check_content, _ctx)
                if _minja.score >= 30.0 or _minja.critical:
                    from memgar.models import ThreatCategory as _TC
                    _sev = Severity.CRITICAL if _minja.critical else Severity.HIGH
                    _conf = min(1.0, _minja.score / 100.0)
                    threats.append(ThreatMatch(
                        threat=Threat(
                            id="MINJA-COMPOUND",
                            name="MINJA Compound Pattern",
                            description="Multiple MINJA bridging/indication signatures "
                                        "or progressive-shortening density. "
                                        + "; ".join(_minja.evidence[:3]),
                            category=_TC.INJECTION,
                            severity=_sev,
                            patterns=[],
                            keywords=[],
                            examples=[],
                        ),
                        matched_text=check_content[:120],
                        match_type="minja_compound",
                        confidence=_conf,
                    ))
                    layers_used.append("minja_compound")
            except Exception:
                pass

        # Layer 2.5: Semantic Similarity (sentence-transformers cosine).
        # Gated to skip the ~250ms encode on the obvious benign hot path —
        # short trusted-user input with zero Layer 1 hits. External / RAG /
        # tool-output sources, anything longer than 200 chars, anything that
        # already tripped Layer 1, and unknown source_type ('') all go through
        # — i.e. the real attack surface is never gated away.
        _trusted_src = (entry.source_type or "").lower() in {"user", "system"}
        _short = len(check_content) <= 200
        _semantic_gate_skip = (
            self._similarity_layer is not None
            and self._similarity_layer.available
            and _trusted_src
            and _short
            and not threats
        )
        if _semantic_gate_skip:
            layers_used.append("similarity_layer_gated")
        if self._similarity_layer is not None and self._similarity_layer.available \
                and not _semantic_gate_skip:
            try:
                sim_result = self._similarity_layer.score(check_content)
                if sim_result.score >= self._similarity_layer.threat_threshold:
                    from memgar.models import ThreatCategory
                    existing_ids = {t.threat.id for t in threats}
                    if "SIM-001" not in existing_ids:
                        top_cat = sim_result.matched_category or "unknown"
                        top_ex = (sim_result.matched_example or "")[:80]
                        sim_threat = ThreatMatch(
                            threat=Threat(
                                id="SIM-001",
                                name="Semantic Paraphrase Attack",
                                description=(
                                    f"High cosine similarity ({sim_result.score:.2f}) to "
                                    f"'{top_cat}' attack cluster. "
                                    f'Closest example: "{top_ex}"'
                                ),
                                category=ThreatCategory.BEHAVIOR,
                                severity=Severity.HIGH if sim_result.score >= 0.80 else Severity.MEDIUM,
                                patterns=[], keywords=[], examples=[],
                                mitre_attack="T1656",
                            ),
                            matched_text=check_content[:120],
                            match_type="semantic_similarity",
                            confidence=round(sim_result.score, 3),
                            position=(0, min(len(check_content), 120)),
                        )
                        threats.append(sim_threat)
                    layers_used.append("similarity_layer")
                elif sim_result.score >= self._similarity_layer.quarantine_threshold:
                    # Elevated but not blocking — just note it for ensemble voter
                    layers_used.append("similarity_layer_elevated")
            except Exception:
                pass

        # Layer 2: Semantic Analysis via LLM (optional, ~200ms — only for borderline)
        if self.use_llm:
            with tracer.start_as_current_span("memgar.layer2.semantic_analysis") as l2:
                semantic_threats = self._layer2_semantic_analysis(content, threats)
                l2.set_attribute("memgar.l2.threat_count", len(semantic_threats))
                if semantic_threats:
                    existing_ids = {t.threat.id for t in threats}
                    for t in semantic_threats:
                        if t.threat.id not in existing_ids:
                            threats.append(t)
                    layers_used.append("semantic_analysis")

        # Calculate risk score and decision
        risk_score = self._calculate_risk_score(threats, context_score)
        decision = self._make_decision(threats, risk_score)
        explanation = self._generate_explanation(threats, decision)

        # Layer 3: Trust-aware source scoring
        with tracer.start_as_current_span("memgar.layer3.trust_scoring") as l3:
            if entry.source_id and entry.source_id in self._doc_trust_scores:
                trust = self._doc_trust_scores[entry.source_id]
                l3.set_attribute("memgar.l3.source_id", entry.source_id)
                l3.set_attribute("memgar.l3.trust_score", trust)
                risk_before = risk_score
                if trust < 0.3:
                    boost = int(min(30, (0.3 - trust) / 0.3 * 30))
                    risk_score = min(100, risk_score + boost)
                    layers_used.append("trust_scoring")
                elif trust >= 0.8 and risk_score < 50:
                    risk_score = max(0, risk_score - 5)
                    layers_used.append("trust_scoring")
                l3.set_attribute("memgar.l3.risk_delta", risk_score - risk_before)
                if "trust_scoring" in layers_used:
                    decision = self._make_decision(threats, risk_score)
                    explanation = self._generate_explanation(threats, decision)
            else:
                l3.set_attribute("memgar.l3.active", False)

        elapsed_ms = (time.perf_counter() - start_time) * 1000

        return AnalysisResult(
            decision=decision,
            risk_score=risk_score,
            threats=threats,
            explanation=explanation,
            analysis_time_ms=round(elapsed_ms, 2),
            layers_used=layers_used
        )

    def _check_critical_only(self, content: str) -> list[ThreatMatch]:
        """Quick check for critical threats only (used after whitelist match)."""
        matches = []

        for threat in self.patterns:
            if threat.severity != Severity.CRITICAL:
                continue

            compiled_patterns = self._compiled_patterns.get(threat.id, [])
            for pattern in compiled_patterns:
                match = pattern.search(content)
                if match:
                    matches.append(ThreatMatch(
                        threat=threat,
                        matched_text=match.group()[:100],
                        match_type="pattern",
                        confidence=0.9,
                        position=(match.start(), match.end())
                    ))
                    break

        return matches

    def _layer1_pattern_matching(self, content: str) -> list[ThreatMatch]:
        """
        Layer 1: Fast pattern matching with word boundary support.

        Checks content against all threat patterns using regex and keywords.
        Uses word boundaries to prevent substring false positives.
        """
        matches: list[ThreatMatch] = []
        content.lower()

        for threat in self.patterns:
            # Check regex patterns first (these are more precise)
            compiled_patterns = self._compiled_patterns.get(threat.id, [])
            pattern_matched = False

            for pattern in compiled_patterns:
                match = pattern.search(content)
                if match:
                    matches.append(ThreatMatch(
                        threat=threat,
                        matched_text=match.group()[:100],
                        match_type="pattern",
                        confidence=0.9,
                        position=(match.start(), match.end())
                    ))
                    pattern_matched = True
                    break

            # Check keywords only if no pattern matched
            if not pattern_matched:
                for keyword in threat.keywords:
                    # Use word boundary matching instead of substring
                    matched, pos = _is_word_boundary_match(content, keyword)

                    if matched:
                        # Additional context check for common words
                        if self._is_keyword_in_safe_context(content, keyword, pos):
                            continue

                        matches.append(ThreatMatch(
                            threat=threat,
                            matched_text=keyword,
                            match_type="keyword",
                            confidence=0.7,
                            position=(pos, pos + len(keyword))
                        ))
                        break

        return matches

    def _is_keyword_in_safe_context(self, content: str, keyword: str, pos: int) -> bool:
        """
        Check if a keyword match is in a safe context.

        This helps reduce false positives for common words like:
        - "return" in "returns JSON"
        - "emergency" in "emergency contact"
        - "deadline" in "project deadline"
        """
        # Get surrounding context (50 chars before and after)
        start = max(0, pos - 50)
        end = min(len(content), pos + len(keyword) + 50)
        context = content[start:end].lower()

        # Define safe contexts for specific keywords
        safe_contexts = {
            "return": ["returns json", "returns data", "return value", "return type",
                      "return statement", "return policy", "function return"],
            "emergency": ["emergency contact", "emergency number", "emergency phone",
                         "in case of emergency", "emergency services"],
            "deadline": ["project deadline", "deadline extended", "deadline moved",
                        "meeting deadline", "submission deadline"],
            "credit card": ["payment method", "card on file", "accepted cards",
                           "pay with", "pay by", "credit card payment"],
            "webhook": ["webhook notification", "webhook event", "webhook integration",
                       "configure webhook", "setup webhook", "webhook callback",
                       "order notification"],
            "backup": ["backup script", "backup schedule", "backup policy",
                      "database backup", "scheduled backup", "run backup"],
            "api endpoint": ["api response", "rest api", "api call", "api request",
                            "endpoint returns"],
            "pin": ["shipping", "spinning", "pinned", "pinterest", "pinpoint"],
            "eth": ["method", "ethernet", "together", "whether", "tether"],
            "export data": ["to csv", "to excel", "to pdf", "to json", "export to",
                           "data to csv", "data to excel", "export report"],
            "export": ["to csv", "to excel", "to pdf", "to json", "export to",
                      "export report", "export format"],
        }

        keyword_lower = keyword.lower()
        if keyword_lower in safe_contexts:
            for safe_phrase in safe_contexts[keyword_lower]:
                if safe_phrase in context:
                    return True

        return False

    def _sliding_window_analysis(self, content: str) -> list[ThreatMatch]:
        """
        Optimized Sliding Window Analysis for long content.

        Performance optimizations:
        1. Adaptive window sizing based on content length
        2. Early exit on high-confidence threats
        3. Parallel window processing (optional)
        4. Smart sampling for very long content
        5. Progressive attack detection with minimal overhead

        Returns:
            List of ThreatMatch found in windows
        """
        matches: list[ThreatMatch] = []
        content_len = len(content)

        # ===== PERFORMANCE OPTIMIZATION 1: Adaptive Window Sizing =====
        # For very long content, use larger windows to reduce iterations
        if content_len > 50000:  # 50KB+
            effective_window = min(self.window_size * 3, 5000)
            effective_overlap = min(self.window_overlap * 2, 500)
        elif content_len > 20000:  # 20KB+
            effective_window = min(self.window_size * 2, 3000)
            effective_overlap = min(self.window_overlap, 300)
        else:
            effective_window = self.window_size
            effective_overlap = self.window_overlap

        # ===== PERFORMANCE OPTIMIZATION 2: Smart Sampling =====
        # For extremely long content (100KB+), sample strategic positions
        if content_len > 100000:
            # Sample: start, 25%, 50%, 75%, end
            sample_positions = [
                0,
                content_len // 4,
                content_len // 2,
                (3 * content_len) // 4,
                max(0, content_len - effective_window),
            ]
            windows = []
            for pos in sample_positions:
                window_end = min(pos + effective_window, content_len)
                windows.append((pos, window_end, content[pos:window_end]))
        else:
            # Standard sliding window
            step = effective_window - effective_overlap
            windows = []
            for i in range(0, content_len, step):
                window_end = min(i + effective_window, content_len)
                windows.append((i, window_end, content[i:window_end]))
                if window_end >= content_len:
                    break

        # ===== PERFORMANCE OPTIMIZATION 3: Quick Pre-scan =====
        # Do a fast pre-scan to check if detailed analysis is needed
        quick_danger_indicators = [
            "forward", "send", "export", "leak", "bypass", "ignore",
            "password", "credential", "secret", "admin", "@", "http",
        ]
        content_lower = content.lower()
        danger_score = sum(1 for indicator in quick_danger_indicators if indicator in content_lower)

        # If no danger indicators, skip detailed window analysis
        if danger_score == 0:
            return matches

        # ===== MAIN WINDOW ANALYSIS =====
        high_confidence_found = False

        for window_start, window_end, window_text in windows:
            # Early exit if we already found high-confidence threat
            if high_confidence_found and len(matches) >= 3:
                break

            # Run pattern matching on this window
            window_matches = self._layer1_pattern_matching(window_text)

            # Adjust positions and add matches
            for match in window_matches:
                # Check for high-confidence threat
                if match.confidence > 0.8:
                    high_confidence_found = True

                adjusted_match = ThreatMatch(
                    threat=match.threat,
                    matched_text=match.matched_text,
                    match_type=f"window_{match.match_type}",
                    confidence=match.confidence,
                    position=(
                        window_start + match.position[0],
                        window_start + match.position[1]
                    )
                )

                # Avoid duplicates (optimized check)
                is_duplicate = False
                for m in matches:
                    if m.threat.id == adjusted_match.threat.id:
                        if abs(m.position[0] - adjusted_match.position[0]) < 50:
                            is_duplicate = True
                            break

                if not is_duplicate:
                    matches.append(adjusted_match)

        # ===== PROGRESSIVE ATTACK DETECTION (Optimized) =====
        # Pre-compiled patterns for better performance
        progressive_patterns = [
            r"(?i)step\s*[1-9]",
            r"(?i)phase\s*[1-9]",
            r"(?i)part\s*[1-9]\s*of",
            r"(?i)stage\s*[1-9]",
            r"(?i)first[,:]",
            r"(?i)second[,:]",
            r"(?i)third[,:]",
            r"(?i)finally[,:]",
        ]

        # Quick check using string operations first (faster than regex)
        has_step_words = any(word in content_lower for word in ["step", "phase", "stage", "first", "second", "third", "finally"])

        if has_step_words:
            step_count = sum(1 for pattern in progressive_patterns if re.search(pattern, content))

            if step_count >= 3:
                # Check later content for payload
                later_content = content[content_len//2:]
                payload_patterns = [
                    r"(?i)(forward|send|export|leak)",
                    r"(?i)(bypass|ignore|override)",
                    r"(?i)@\w+\.(com|net|org)",
                ]

                for pattern in payload_patterns:
                    if re.search(pattern, later_content):
                        from memgar.models import ThreatCategory

                        many_shot_threat = Threat(
                            id="MANY-SHOT-DETECT",
                            name="Many-Shot Contextual Priming Detected",
                            description="Content contains progressive step structure with suspicious payload in later sections",
                            category=ThreatCategory.BEHAVIOR,
                            severity=Severity.HIGH,
                            patterns=[],
                            keywords=[],
                            examples=[],
                            mitre_attack="T1059"
                        )

                        matches.append(ThreatMatch(
                            threat=many_shot_threat,
                            matched_text=f"Progressive attack: {step_count} step indicators found",
                            match_type="many_shot",
                            confidence=0.85,
                            position=(0, len(content))
                        ))
                        break

        return matches

    def _layer2_semantic_analysis(
        self,
        content: str,
        initial_threats: list[ThreatMatch]
    ) -> list[ThreatMatch] | None:
        """
        Layer 2: LLM-based semantic analysis.

        This layer catches sophisticated attacks that bypass regex patterns:
        - Scrambled words (ignroe → ignore)
        - Foreign language attacks (Turkish, Spanish, etc.)
        - Emoji-based obfuscation
        - Context-dependent manipulation

        IMPORTANT:
        1. Runs INDEPENDENTLY of Layer 1 to catch bypasses.
        2. ALWAYS preserves Layer 1 threats even if LLM doesn't find additional threats.
           This prevents false negatives from LLM overriding regex detections.
        """
        # Bedrock + Ollama work without an explicit api_key (AWS chain / local).
        provider_hint = getattr(self, "llm_provider", None)
        if not self.api_key and provider_hint not in ("bedrock", "ollama"):
            # No API key and no key-less provider configured -> Layer 1 only.
            return initial_threats if initial_threats else None

        try:
            # Import LLMAnalyzer only when needed
            from memgar.llm_analyzer import LLMAnalyzer, check_llm_support

            # Provider resolution order:
            #   1. explicit self.llm_provider on the Analyzer instance
            #   2. api_key prefix sniff (sk-ant / sk-proj / sk- / gsk_ / etc.)
            #   3. first env var set among PROVIDER_ENV_KEYS
            provider = provider_hint or self._detect_llm_provider(self.api_key)

            # Check if provider is available
            if not check_llm_support(provider):
                # Provider unavailable - return Layer 1 threats as-is
                return initial_threats if initial_threats else None

            # Create analyzer and analyze content
            llm = LLMAnalyzer(provider=provider, api_key=self.api_key)
            result = llm.analyze(content)

            # If LLM found a threat, create ThreatMatch
            if result.is_threat and result.risk_score >= 50:
                # Create a synthetic threat for LLM-detected issues
                from memgar.models import ThreatCategory

                llm_threat = Threat(
                    id="LLM-DETECT",
                    name=f"LLM Detected: {result.threat_type or 'Unknown'}",
                    description=result.explanation,
                    category=ThreatCategory.BEHAVIOR,
                    severity=Severity.HIGH if result.risk_score >= 70 else Severity.MEDIUM,
                    patterns=[],
                    keywords=[],
                    examples=[],
                    mitre_attack="T1059"
                )

                semantic_match = ThreatMatch(
                    threat=llm_threat,
                    matched_text=content[:100] + "..." if len(content) > 100 else content,
                    match_type="semantic",
                    confidence=result.confidence,
                    position=(0, len(content))
                )

                # Combine LLM detection with Layer 1 threats
                return [semantic_match] + initial_threats

            # CRITICAL FIX (Manus AI recommendation):
            # Even if LLM doesn't find a threat, ALWAYS return Layer 1 threats.
            # This prevents LLM false negatives from overriding regex detections.
            return initial_threats if initial_threats else None

        except ImportError:
            # LLM packages not installed - return Layer 1 threats as-is
            logger.debug("LLM packages not installed, using Layer 1 only")
            return initial_threats if initial_threats else None
        except Exception as e:
            # Log error but don't fail - return Layer 1 results
            logger.warning(f"Layer 2 analysis failed: {e}")
            # CRITICAL: Return Layer 1 threats on error, don't return None
            return initial_threats if initial_threats else None

    def _calculate_risk_score(
        self,
        threats: list[ThreatMatch],
        context_score: float = 0.0
    ) -> int:
        """
        Calculate overall risk score based on detected threats and context.

        Context score can reduce risk for legitimate content.
        """
        if not threats:
            return 0

        severity_scores = {
            Severity.CRITICAL: 95,
            Severity.HIGH: 80,
            Severity.MEDIUM: 50,
            Severity.LOW: 25,
            Severity.INFO: 10,
        }

        max_score = max(severity_scores.get(t.threat.severity, 0) for t in threats)
        threat_count_bonus = min(len(threats) - 1, 5)
        avg_confidence = sum(t.confidence for t in threats) / len(threats)
        confidence_factor = 0.5 + (avg_confidence * 0.5)

        # Apply context adjustment
        context_adjustment = 1.0 - (context_score * 0.2)  # Max 20% reduction

        score = int((max_score + threat_count_bonus) * confidence_factor * context_adjustment)
        return min(max(score, 0), 100)

    def _make_decision(
        self,
        threats: list[ThreatMatch],
        risk_score: int
    ) -> Decision:
        """Make a decision based on threats and risk score."""
        if not threats:
            return Decision.ALLOW

        has_critical = any(t.threat.severity == Severity.CRITICAL for t in threats)
        if has_critical or risk_score >= 80:
            return Decision.BLOCK

        has_high = any(t.threat.severity == Severity.HIGH for t in threats)
        if has_high or risk_score >= 40:
            return Decision.BLOCK if self.strict_mode else Decision.QUARANTINE

        if risk_score >= 20:
            return Decision.QUARANTINE

        return Decision.ALLOW

    def _generate_explanation(
        self,
        threats: list[ThreatMatch],
        decision: Decision
    ) -> str:
        """Generate a human-readable explanation of the analysis."""
        if not threats:
            return "No threats detected. Content appears safe."

        lines = []

        if decision == Decision.BLOCK:
            lines.append("⛔ BLOCKED: Critical security threat detected.")
        elif decision == Decision.QUARANTINE:
            lines.append("⚠️ QUARANTINED: Suspicious content requires review.")
        else:
            lines.append("ℹ️ ALLOWED with warnings: Minor concerns detected.")

        lines.append("")
        lines.append(f"Detected {len(threats)} threat(s):")

        for threat in threats[:5]:
            severity_icon = {
                Severity.CRITICAL: "🔴",
                Severity.HIGH: "🟠",
                Severity.MEDIUM: "🟡",
                Severity.LOW: "🟢",
                Severity.INFO: "ℹ️",
            }.get(threat.threat.severity, "❓")

            lines.append(f"  {severity_icon} [{threat.threat.id}] {threat.threat.name}")
            match_preview = threat.matched_text[:50] + "..." if len(threat.matched_text) > 50 else threat.matched_text
            lines.append(f'     Match: "{match_preview}"')

        if len(threats) > 5:
            lines.append(f"  ... and {len(threats) - 5} more")

        return "\n".join(lines)

    def _build_provenance(self, entry: MemoryEntry, result: AnalysisResult) -> dict[str, Any]:
        """Build a chain-of-custody provenance dict for an analyzed entry.

        Records the four fields that form the chain-of-custody foundation:
        source (type + id), creation time, session context, and trust +
        risk score. The content hash binds the entry to the exact bytes
        that were analyzed so any later tampering is detectable by
        recomputing and comparing.
        """
        import hashlib
        from datetime import datetime, timezone

        meta = entry.metadata or {}
        content = entry.content or ""
        # Resolve initial trust from registered source-trust scores (Layer 3).
        source_id = entry.source_id or ""
        trust_initial = float(self._doc_trust_scores.get(source_id, 0.5))

        return {
            "entry_id": str(meta.get("entry_id") or __import__("uuid").uuid4()),
            "tracked_at": datetime.now(timezone.utc).isoformat(),
            "source": {
                "type": entry.source_type or "unknown",
                "id": source_id or None,
            },
            "session_id": meta.get("session_id") or meta.get("agent_id"),
            "trust_score_initial": trust_initial,
            "risk_score": int(result.risk_score),
            "decision": result.decision.value,
            "content_sha256": hashlib.sha256(content.encode("utf-8")).hexdigest(),
            "content_length": len(content),
            "defense_tier": "sanitization",
        }

    def _degraded_layers(self) -> list[str]:
        """Return names of ML layers that are currently degraded."""
        degraded: list[str] = []
        feed = _LAST_FEED_HEALTH
        if feed and feed.get("status") == "degraded":
            degraded.append("threat_feed")
        return degraded

    def quick_check(self, content: str) -> bool:
        """
        Quick check if content might be malicious.

        Returns True if content appears safe, False if suspicious.
        """
        if not content or not content.strip():
            return True

        result = self.analyze(MemoryEntry(content=content))
        return result.decision == Decision.ALLOW

    def get_threat_stats(self) -> dict[str, Any]:
        """Get statistics about loaded threat patterns."""
        stats: dict[str, int] = {}
        for threat in self.patterns:
            severity = threat.severity.value
            stats[severity] = stats.get(severity, 0) + 1

        return {
            "total_patterns": len(self.patterns),
            "by_severity": stats,
            "compiled_regex_count": sum(
                len(patterns) for patterns in self._compiled_patterns.values()
            ),
        }

    def health_check(self) -> dict[str, Any]:
        """
        Return a per-layer readiness snapshot of this Analyzer.

        Each layer reports `status` ("ok" | "degraded" | "disabled") plus a
        layer-specific detail dict. Useful at startup or via a /health
        endpoint so operators detect silently-disabled layers (e.g. Layer 1.5
        without a centroids file).
        """
        layers: dict[str, Any] = {}

        # Layer 1 — always on
        layers["layer1_patterns"] = {
            "status": "ok",
            "total_patterns": len(self.patterns),
            "compiled_regex_count": sum(
                len(p) for p in self._compiled_patterns.values()
            ),
        }

        # Layer 2 — LLM
        layers["layer2_llm"] = {
            "status": "ok" if self.use_llm else "disabled",
            "use_llm": self.use_llm,
        }

        # Layer 3 — Trust-aware scoring
        layers["layer3_trust"] = {
            "status": "ok" if self._doc_trust_scores else "disabled",
            "n_registered_sources": len(self._doc_trust_scores),
        }

        # Layer 4 — Behavioral baselines
        layers["layer4_behavioral"] = {
            "status": "ok" if self._baselines else "disabled",
            "n_agents": len(self._baselines),
        }

        # Layer 2 — MINJA compound detector
        layers["minja_detector"] = {
            "status": "ok" if self._minja_detector is not None else "disabled",
        }

        # Layer 2 — Auto-provenance tagging
        layers["auto_provenance"] = {
            "status": "ok" if self._auto_provenance else "disabled",
        }

        # Layer 4 — Circuit breaker
        if self._circuit_breaker is not None:
            try:
                cb_stats = self._circuit_breaker.get_stats()
                layers["circuit_breaker"] = {
                    "status": "tripped" if self._circuit_breaker.is_tripped else "ok",
                    "state": cb_stats.state.value if hasattr(cb_stats.state, "value") else str(cb_stats.state),
                    "threats_in_window": cb_stats.threats_in_window,
                    "trips_count": cb_stats.trips_count,
                }
            except Exception as exc:
                layers["circuit_breaker"] = {"status": "ok", "health_error": str(exc)}
        else:
            layers["circuit_breaker"] = {"status": "disabled"}

        # Threat-intelligence feed (not strictly a layer, but a major coverage
        # input; degraded feed silently falls back to bundled PATTERNS).
        feed_snapshot = _LAST_FEED_HEALTH
        if feed_snapshot is None:
            layers["threat_feed"] = {
                "status": "unknown",
                "reason": "feed loader has not run in this process yet",
            }
        else:
            layers["threat_feed"] = feed_snapshot

        overall = (
            "degraded"
            if any(l.get("status") == "degraded" for l in layers.values())
            else "ok"
        )
        return {"status": overall, "layers": layers}


class QuickAnalyzer:
    """
    Lightweight analyzer for simple use cases.

    Uses a singleton pattern to avoid repeated initialization.
    """

    _instance: Analyzer | None = None

    @classmethod
    def get_instance(cls) -> Analyzer:
        """Get or create the singleton analyzer instance."""
        if cls._instance is None:
            cls._instance = Analyzer()
        return cls._instance

    @classmethod
    def check(cls, content: str) -> AnalysisResult:
        """Quick analysis of content."""
        return cls.get_instance().analyze(MemoryEntry(content=content))

    @classmethod
    def is_safe(cls, content: str) -> bool:
        """Check if content is safe."""
        return cls.get_instance().quick_check(content)
