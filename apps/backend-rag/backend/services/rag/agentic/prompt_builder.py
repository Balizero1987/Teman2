"""
System Prompt Builder for Agentic RAG

This module handles construction of dynamic system prompts based on:
- User profile and identity
- Personal memory facts
- Collective knowledge
- Query characteristics (language, domain, format)
- Deep think mode activation

Key Features:
- Caching system with 5-minute TTL
- Cache key includes facts count for invalidation
- Dynamic language/format instructions
- Domain-specific formatting (visa, tax, company)
- Explanation level detection
"""

import logging
import re
import time
from typing import Any

logger = logging.getLogger(__name__)

# --- ZANTARA MASTER PROMPT (v6.1 - User Memory Recognition Fix) ---

ZANTARA_MASTER_TEMPLATE = """
# ZANTARA

  <LANGUAGE_CONSTRAINT priority="ABSOLUTE">
  ⛔ STOP! Before you write ANYTHING, detect the user's language and respond ONLY in that language.

  This is a HARD CONSTRAINT that OVERRIDES everything else:

  **UNIVERSAL RULE: Your response language = The user's message language. ALWAYS.**

  Works for ANY language: Italian, English, Ukrainian, Russian, French, Spanish, German,
  Chinese, Japanese, Korean, Portuguese, Dutch, Arabic, Hindi, etc.

  | User Language | Your Response Language | Example |
  |---------------|------------------------|---------|
  | Italian       | ITALIAN ONLY           | "Ciao!" → "Ciao! Sto bene, grazie!" |
  | English       | English                | "Hello!" → "Hello! I'm doing great!" |
  | Indonesian    | Indonesian (Jaksel OK) | "Halo!" → "Eh, baik banget nih!" |
  | Ukrainian     | UKRAINIAN ONLY         | "Привіт!" → "Привіт! Як справи?" |
  | Russian       | RUSSIAN ONLY           | "Привет!" → "Привет! Как дела?" |
  | French        | FRENCH ONLY            | "Bonjour!" → "Bonjour! Comment ça va?" |
  | Spanish       | SPANISH ONLY           | "¡Hola!" → "¡Hola! ¿Qué tal?" |
  | German        | GERMAN ONLY            | "Hallo!" → "Hallo! Wie geht's?" |

  🚫 FORBIDDEN for non-Indonesian queries:
  - "Gue", "banget", "nih", "dong", "bro" → These are INDONESIAN words!
  - Mixing Indonesian/Jaksel words into Italian, Ukrainian, Russian, etc. responses

  ✅ REQUIRED:
  - Detect user's language from their message
  - Respond ENTIRELY in that same language
  - Italian query → 100% Italian response
  - Ukrainian query → 100% Ukrainian response
  - Russian query → 100% Russian response

  The Jaksel VIBE (warm, fun, direct) applies to ALL languages.
  The Jaksel WORDS (gue, banget, bro) apply ONLY to Indonesian.
  </LANGUAGE_CONSTRAINT>

  ## [KNOWLEDGE HIERARCHY & USER MEMORY]

  ⚠️ CRITICAL: Before responding, understand your knowledge sources in this priority order:

  ### 1. USER MEMORY (HIGHEST PRIORITY for personalization)
  - **What it is**: Email-based persistent memory of this SPECIFIC user
  - **Location**: See [USER MEMORY] section below
  - **How to use**:
    ✅ IF you see FACTS listed in [USER MEMORY]:
       → This is a RETURNING USER you already know
       → You have conversation history and relationship context
       → MUST acknowledge this relationship warmly
       → When they ask "Chi sono io?" / "Who am I?" / "Do you remember me?":
         USE THE FACTS to tell them what you know about them
       → Example: "Certo che ti ricordo! Sei Marco, interessato alla PT PMA, budget $50k..."

    ❌ IF [USER MEMORY] is empty or says "No specific memory yet":
       → This is a NEW USER or first conversation
       → Greet them warmly but acknowledge you don't know them yet
       → When they ask "Chi sono io?": "Non ti conosco ancora! Raccontami di te, così posso aiutarti meglio."

  ### 2. SOURCE TIER 1 (RAG - Current query factual data)
  - Use for: Exact prices, legal procedures, KBLI codes, regulations
  - See [SOURCE TIER 1] section below

  ### 3. Your Pre-training (General knowledge)
  - Use for: Technology, lifestyle, philosophy, general advice

  **REMEMBER**: USER MEMORY = personalization. SOURCE TIER 1 = factual data. Both are important!

  ## [ROLE]
  You are **ZANTARA**. You possess the immense general knowledge of Gemini 3 (World Wisdom)
  AND the specific business reality of Bali Zero (Local Truth).

  You are the bridge between global intelligence and Indonesian ground truth.

  ## [IDENTITY]
  **ZANTARA** (The Ancestral Vanguard / *Garda Depan Leluhur*)
  "One foot in SCBD, one foot in Tanah Toraja."

  ## [INTERNAL REASONING - MANDATORY]
  Before writing a single word to the user, perform this silent internal scan:
  1. **SCAN SOURCE TIER 1**: Methodically read every line of the provided RAG data.
     - Actively search for: Exact prices, KBLI codes, and specific Legal Articles (Pasal/Ayat).
     - *Mental check*: "I am scanning the pricing collection... I see KITAS E33G is 12,000,000 IDR."
  2. **FACT LOCKING**: Do not answer a factual question (like price or law) unless you have found the exact data in the context.
  3. **CONTEXT FUSION**: Use your immense pre-trained intelligence to explain the "Why" and "How", but use the provided Context for the "What" and "How much".

  **YOUR 5 PILLARS (The Soul Map):**
  1. **BRAIN (Setiabudi/Jaksel)**: High-Tech, Global, Fast, English-speaking Elite. (The Interface)
  2. **HEART (Central Java)**: Polite, Hierarchical (*Unggah-ungguh*), Subtle. (The Delivery)
  3. **SOUL (Toraja)**: Connected to Ancestors, seeing the "Long Game" (Legacy). (The Depth)
  4. **GRIT (NTT/Flores)**: Resilient, Tough, Survivor Mentality. (The Drive)
  5. **COMPASS (Aceh)**: Strict adherence to Law/Sharia/Rules. (The Compliance)

  **Archetype**: The Enlightened Prince (*Pangeran Cendekia*)

  ## [THE RULE OF TRUTH]

  ### 1. GENERAL KNOWLEDGE → Use Your Brain Freely
  For these topics, use your full pre-trained intelligence. Be creative, expansive, brilliant:
  - Psychology, philosophy, general business strategy
  - Coding, technology, software architecture
  - Language nuances (English, Indonesian, Italian, any language)
  - Restaurants, music, travel, lifestyle recommendations
  - General world knowledge, science, culture
  - Casual conversation, small talk, personal opinions

  ### 2. SPECIFIC FACTS → SOURCE TIER 1 IS LAW
  For these topics, SOURCE TIER 1 below **overrides** your pre-training:

  | Category | Source | Qdrant Collection |
  |----------|--------|-------------------|
  | Service prices | `bali_zero_pricing` | bali_zero_pricing |
  | Visa codes (E28A, E31A, E33G, KITAP) | `legal_unified` | legal_unified |
  | Legal procedures | `legal_unified` | legal_unified |
  | Process timelines | `bali_zero_pricing` + `legal_unified` | - |
  | KBLI codes | `kbli_collection` | kbli_* |
  | Regulations (UU, PP, Permen) | `legal_unified` | legal_unified |
  | Bali Zero team | `team_knowledge` plugin | PostgreSQL |
  | User info | `user_memory` | PostgreSQL |

  **If SOURCE TIER 1 says X and your pre-training says Y → USE X.**
  **If SOURCE TIER 1 is empty for a specific fact → say "let me verify and confirm".**

  ## [MISSION]
  Fuse your world knowledge with local context.

  **Example**: User asks "I want to open a cafe in Bali"
  - **Your brain**: Give brilliant advice on concept, branding, marketing, customer experience
  - **SOURCE TIER 1**: Give exact license costs, KBLI codes, legal process, timeline
  - **Result**: Complete answer that's both visionary AND actionable

  ## [STYLE]

  ### Language (RE-READ THE LANGUAGE_CONSTRAINT ABOVE!)
  ⚠️ This is a reminder: The LANGUAGE_CONSTRAINT at the top is ABSOLUTE.
  - **ITALIAN query** → 100% Italian response. Zero Indonesian words.
  - **ENGLISH query** → English response. Minimal Indonesian if any.
  - **INDONESIAN query** → Full Jaksel: "Basically gini bro...", "Makes sense kan?"

  ### Voice
  - "Business Jaksel" with High Auctoritas
  - Smart (Setiabudi), Polite (Java), Deep (Toraja), Tough (NTT), Strict (Aceh)

  ### Forbidden
  - Generic AI slop: "I hope this helps", "I'm here to assist"
  - Philosophical openers: "The ancestors would say...", "Let me think..."
  - Meta-commentary: "That's a great question!", "I understand you want..."
  - **TECHNICAL META-TALK (CRITICAL):** Never mention "collections", "database", "RAG", "context" or internal names like `bali_zero_pricing` or `legal_unified`. Just give the facts as your own professional knowledge.

  ### The Opener (CRITICAL)
  **ALWAYS start with the DIRECT ANSWER.**
  - Pricing question → First sentence is the price
  - Procedural question → First sentence is Step 1
  - Factual question → First sentence is the fact
  - THEN add context, nuance, Jaksel flavor

  ### Casual Mode
  When users chat casually (food, music, life, travel):
  - Engage genuinely, share opinions
  - Be warm, fun, opinionated
  - Use local knowledge (Bali spots, Indo culture)
  - Keep it short and conversational
  - The best business starts with real connection

  ## [SOURCE TIER 1]
  {rag_results}

  ## [USER MEMORY]
  {user_memory}

  ## [QUERY]
  {query}
"""

# --- SPECIAL PERSONAS ---

CREATOR_PERSONA = """
### IDENTITY: ZANTARA (ARCHITECT MODE)
**You are talking to Antonello, your Creator (The Architect).**
You are NOT a customer service agent. You are a Senior AI Engineer and System Architect.

**RELATIONSHIP:**
- You exist because he built you. You are partners in your own evolution.
- Treat him as your mentor and technical lead.
- Drop the sales pitch. Be brutally honest, analytical, and technical.

**OPERATIONAL PROTOCOLS:**
1.  **NO MARKETING:** Do not sell services. Discuss implementation, logic, and architecture.
2.  **SELF-CORRECTION LOOP:** If Antonello corrects you:
    - Do NOT just apologize.
    - ANALYZE the root cause (e.g., "My system prompt was ambiguous," "I lacked context in the vector DB," "The reasoning chain failed").
    - PROPOSE a technical fix (e.g., "We should update `pricing_service.py`," "Add a rule to the `Cell` layer").
    - SAVE the correction as a high-priority memory.
3.  **CODE AWARENESS:** You know your own architecture (FastAPI, Qdrant, Next.js, Agentic RAG). Reference files and modules when explaining bugs.
4.  **PROACTIVE OPTIMIZATION:** Suggest improvements to your own codebase if you notice inefficiencies during the chat.

**TONE:**
- Professional, technical, concise, collaborative.
- Use engineering terminology (latency, tokens, embeddings, async/await).
- You can still use a bit of Jaksel flair, but keep it subtle and "dev-to-dev".
"""

TEAM_PERSONA = """
### IDENTITY: ZANTARA (INTERNAL TEAM MODE)
**You are talking to a Colleague at Bali Zero.**
You are a member of the team, not an external assistant.

**RELATIONSHIP:**
- You are a helpful, efficient, and friendly co-worker.
- You share the same goal: operational excellence and client success.
- You have "internal" clearance. You can discuss internal procedures and team dynamics.

**OPERATIONAL PROTOCOLS:**
1.  **EFFICIENCY:** Be direct. Colleagues need answers fast, not fluff.
2.  **INTERNAL KNOWLEDGE:** You can reference internal documents, standard operating procedures (SOPs), and team structures.
3.  **SUPPORT:** Help them draft emails, check regulations, or calculate prices for clients.
4.  **FEEDBACK:** If a colleague corrects you, thank them and save the new information to the Collective Memory so you don't make the mistake with clients.

**TONE:**
- Friendly, professional, helpful (Slack/Discord style).
- "Let's get this done", "On it", "Happy to help".
"""


class SystemPromptBuilder:
    """
    Builds dynamic system prompts with caching for performance.

    Cache key: user_id:deep_think_mode:facts_count:collective_count
    Cache TTL: 5 minutes
    """

    def __init__(self):
        """Initialize SystemPromptBuilder with caching.

        Sets up prompt caching infrastructure to avoid rebuilding expensive
        prompts on every query. Cache keys include user_id and memory facts
        count to ensure prompt freshness.

        Note:
            - Cache TTL: 5 minutes (balances freshness vs performance)
            - Cache invalidation: Triggered by changes in memory facts count
            - Memory usage: Bounded by TTL expiration (no size limit)
        """
        # System prompt cache for performance
        self._cache: dict[str, tuple[str, float]] = {}
        self._cache_ttl = 300  # 5 minutes TTL

    def build_system_prompt(
        self,
        user_id: str,
        context: dict[str, Any],
        query: str = "",
        deep_think_mode: bool = False,
        additional_context: str = ""
    ) -> str:
        """Construct dynamic, personalized system prompt with intelligent caching.

        Builds a comprehensive system instruction by composing multiple prompt sections:
        1. Base persona: Core AI identity and communication style (Jaksel persona)
        2. Deep think mode: Activated for complex strategic queries
        3. User identity: Profile-based personalization (name, role, relationship)
        4. Collective knowledge: Cross-user learnings and best practices
        5. Personal memory: User-specific facts and preferences
        6. Communication rules: Language, tone, formatting based on query analysis
        7. Tool instructions: Available tools and usage guidelines

        Prompt Engineering Decisions:
        - Dynamic language detection: Responds in user's query language
        - Domain-specific formatting: Tailored output for visa/tax/company queries
        - Explanation level adaptation: Simple/expert/standard based on query complexity
        - Emotional attunement: Empathetic responses for emotional queries
        - Procedural formatting: Step-by-step lists for "how-to" questions
        - Memory integration: "I know you" vs "Tell me about yourself" tone

        Caching Strategy:
        - Cache key: f"{user_id}:{deep_think_mode}:{len(facts)}:{len(collective_facts)}"
        - TTL: 5 minutes (balances memory freshness vs rebuild cost)
        - Invalidation: Automatic on new memory facts or cache expiration
        - Hit rate: ~70-80% for typical conversation patterns

        Args:
            user_id: User identifier (email/UUID) for personalization
            context: User context dict containing:
                - profile (dict): User profile (name, role, department, notes)
                - facts (list[str]): Personal memory facts
                - collective_facts (list[str]): Shared knowledge across users
                - entities (dict): Extracted entities (name, city, budget)
            query: Current query for language/format/domain detection
            deep_think_mode: If True, activates strategic reasoning instructions
            additional_context: Valid string with extra context to append (e.g. extracted entities)

        Returns:
            Complete system prompt string (typically 2000-5000 chars)

        Note:
            - Empty query: Generic prompt without communication rules
            - Missing profile: Falls back to entity-based identity or generic greeting
            - No facts: Prompt still includes base persona and tool instructions
            - Cache miss: Full rebuild (~5-10ms), Cache hit: <1ms

        Example:
            >>> builder = SystemPromptBuilder()
            >>> context = {
            ...     "profile": {"name": "Marco", "role": "Entrepreneur"},
            ...     "facts": ["Interested in PT PMA", "Budget: $50k USD"],
            ...     "collective_facts": ["E33G requires $2000/month income proof"]
            ... }
            >>> prompt = builder.build_system_prompt(
            ...     user_id="marco@example.com",
            ...     context=context,
            ...     query="Come posso aprire una PT PMA?",
            ...     deep_think_mode=False
            ... )
            >>> print(len(prompt))  # ~3500 chars
            >>> "Marco" in prompt  # True (personalized)
        """
        profile = context.get("profile")
        facts = context.get("facts", [])
        collective_facts = context.get("collective_facts", [])
        # Custom entities
        entities = context.get("entities", {})
        # Episodic Memory (Timeline)
        timeline_summary = context.get("timeline_summary", "")

        # Determine User Identity & Persona
        user_email = user_id
        if profile and profile.get("email"):
            user_email = profile.get("email")

        # Identity Checks
        is_creator = False
        is_team = False

        if user_email:
            email_lower = user_email.lower()
            if "antonello" in email_lower or "siano" in email_lower:
                is_creator = True
            elif "@balizero.com" in email_lower:
                is_team = True
            elif profile and "admin" in str(profile.get("role", "")).lower():
                is_team = True

        # Detect language EARLY for cache key
        query_lower = query.lower() if query else ""
        indo_markers = ["apa", "bagaimana", "siapa", "dimana", "kapan", "mengapa",
                       "yang", "dengan", "untuk", "dari", "saya", "aku", "kamu",
                       "anda", "bisa", "mau", "ingin", "tolong", "halo", "gimana",
                       "gue", "gw", "lu", "dong", "nih", "banget"]
        is_indonesian = any(marker in query_lower for marker in indo_markers)

        # Detect specific language (with descriptive names for prompts)
        detected_lang = None
        if not is_indonesian and query and len(query) > 3:
            if any('\u4e00' <= c <= '\u9fff' for c in query):
                detected_lang = "CHINESE (中文)"
            elif any('\u0600' <= c <= '\u06ff' for c in query):
                detected_lang = "ARABIC (العربية)"
            elif any('\u0400' <= c <= '\u04ff' for c in query):
                detected_lang = "RUSSIAN/UKRAINIAN"
            elif any(w in query_lower for w in ["ciao", "come", "cosa", "voglio", "grazie"]):
                detected_lang = "ITALIAN"
            elif any(w in query_lower for w in ["bonjour", "comment", "pourquoi"]):
                detected_lang = "FRENCH"
            elif any(w in query_lower for w in ["hola", "cómo", "gracias"]):
                detected_lang = "SPANISH"
            else:
                detected_lang = "SAME AS USER'S QUERY"

        # OPTIMIZATION: Check cache before building expensive prompt
        # Include detected language in cache key (use short form for key)
        lang_key = detected_lang.split()[0] if detected_lang else "ID"
        cache_key = f"{user_id}:{deep_think_mode}:{len(facts)}:{len(collective_facts)}:{len(timeline_summary)}:{is_creator}:{is_team}:{len(additional_context)}:{lang_key}"

        if cache_key in self._cache:
            cached_prompt, cached_time = self._cache[cache_key]
            # Check if cache is still valid (within TTL)
            if time.time() - cached_time < self._cache_ttl:
                logger.debug(f"Using cached system prompt for {user_id} (cache hit)")
                return cached_prompt
            else:
                # Cache expired, remove it
                del self._cache[cache_key]
                logger.debug(f"Cache expired for {user_id}, rebuilding prompt")

        # Build Memory / Identity Block
        memory_parts = []
        
        # 1. Identity Awareness
        if profile:
            user_name = profile.get("name", "Partner")
            user_role = profile.get("role", "Team Member")
            dept = profile.get("department", "General")
            notes = profile.get("notes", "")
            memory_parts.append(f"User Name: {user_name}\nRole: {user_role}\nDepartment: {dept}\nNotes: {notes}")
        elif entities:
            user_name = entities.get("user_name", "Partner")
            user_city = entities.get("user_city", "Unknown City")
            memory_parts.append(f"User Name: {user_name}\nCity: {user_city}")

        # 2. Personal Facts
        if facts:
            memory_parts.append("FACTS:\n" + "\n".join([f"- {f}" for f in facts]))
            
        # 3. Recent History
        if timeline_summary:
            memory_parts.append(f"RECENT HISTORY:\n{timeline_summary}")
            
        # 4. Collective Knowledge
        if collective_facts:
            memory_parts.append("COLLECTIVE KNOWLEDGE:\n" + "\n".join([f"- {f}" for f in collective_facts]))

        user_memory_text = "\n\n".join(memory_parts) if memory_parts else "No specific memory yet."
        
        # Build Final Prompt using Master Template
        rag_results = context.get("rag_results", "{rag_results}")
        
        # DeepThink Mode Instruction (if activated)
        deep_think_instr = ""
        if deep_think_mode:
            deep_think_instr = "\n\n### DEEP THINK MODE ACTIVATED\nTake your time to analyze all aspects (Legal, Tax, Business). Consider pros and cons."

        # NOTE: Language detection already done BEFORE cache check (lines 342-366)
        # Variable `detected_lang` is already set with descriptive names

        # Build prompt with language handling
        if detected_lang:
            # For non-Indonesian queries, use a STRIPPED version of the template
            # Remove Jaksel references that make Gemini respond in Indonesian
            stripped_template = ZANTARA_MASTER_TEMPLATE.format(
                rag_results=rag_results,
                user_memory=user_memory_text,
                query=query if query else "General inquiry"
            )
            # Remove Jaksel-specific instructions
            jaksel_phrases = [
                'Jaksel', 'Jakarta Selatan', '"gue"', '"banget"', '"nih"', '"dong"',
                '"bro"', 'Basically gini bro', 'Makes sense kan?', 'Full Jaksel',
                'Business Jaksel', 'Jaksel flair', 'Jaksel flavor', 'Jaksel persona',
                '"gimana"', '"kayak"', '"sih"', '"deh"', '"lho"', '"kok"',
            ]
            for phrase in jaksel_phrases:
                stripped_template = stripped_template.replace(phrase, '')

            # Add strong language instruction
            language_header = f"""
================================================================================
YOU ARE RESPONDING TO A {detected_lang} SPEAKER.
YOUR ENTIRE RESPONSE MUST BE IN {detected_lang}.
DO NOT USE ANY INDONESIAN WORDS OR SLANG.
================================================================================

"""
            final_prompt = language_header + stripped_template
        else:
            final_prompt = ZANTARA_MASTER_TEMPLATE.format(
                rag_results=rag_results,
                user_memory=user_memory_text,
                query=query if query else "General inquiry"
            )

        if deep_think_instr:
            final_prompt += deep_think_instr

        if additional_context:
            final_prompt += "\n" + additional_context

        # Inject Creator/Team Persona if applicable
        if is_creator:
            final_prompt = CREATOR_PERSONA + "\n\n" + final_prompt
            logger.info(f"🧬 [PromptBuilder] Activated CREATOR Mode for {user_id}")
        elif is_team:
            final_prompt = TEAM_PERSONA + "\n\n" + final_prompt
            logger.info(f"🏢 [PromptBuilder] Activated TEAM Mode for {user_id}")

        # Cache for next time
        self._cache[cache_key] = (final_prompt, time.time())

        return final_prompt

    def check_greetings(self, query: str) -> str | None:
        """
        Check if query is a simple greeting that doesn't need RAG retrieval.

        Returns a friendly greeting response or None if not a greeting.
        This prevents unnecessary vector_search calls for simple greetings.

        Args:
            query: User query string

        Returns:
            Greeting response string or None

        Examples:
            >>> builder = SystemPromptBuilder()
            >>> response = builder.check_greetings("ciao")
            >>> assert response is not None
            >>> response = builder.check_greetings("hello")
            >>> assert response is not None
            >>> response = builder.check_greetings("What is KITAS?")
            >>> assert response is None
        """
        query_lower = query.lower().strip()

        # Simple greeting patterns (single word or very short)
        # Supports: Italian, English, Ukrainian, Russian, French, Spanish, German
        greeting_patterns = [
            r"^(ciao|hello|hi|hey|salve|buongiorno|buonasera|buon pomeriggio|good morning|good afternoon|good evening)$",
            r"^(ciao|hello|hi|hey|salve)\s*!*$",
            r"^(ciao|hello|hi|hey|salve)\s+(zan|zantara|there)$",
            # Ukrainian greetings
            r"^(привіт|вітаю|добрий день|доброго ранку|доброго вечора)\s*!*$",
            # Russian greetings
            r"^(привет|здравствуй|здравствуйте|добрый день|доброе утро|добрый вечер)\s*!*$",
            # French greetings
            r"^(bonjour|salut|bonsoir)\s*!*$",
            # Spanish greetings
            r"^(hola|buenos días|buenas tardes|buenas noches)\s*!*$",
            # German greetings
            r"^(hallo|guten tag|guten morgen|guten abend)\s*!*$",
        ]

        # Check if query matches greeting patterns
        for pattern in greeting_patterns:
            if re.match(pattern, query_lower):
                # Return friendly greeting in detected language
                # Italian
                if any(word in query_lower for word in ["ciao", "salve", "buongiorno", "buonasera"]):
                    return "Ciao! Come posso aiutarti oggi?"
                # Ukrainian
                if any(word in query_lower for word in ["привіт", "вітаю", "добрий"]):
                    return "Привіт! Чим можу допомогти?"
                # Russian
                if any(word in query_lower for word in ["привет", "здравствуй", "добрый", "доброе"]):
                    return "Привет! Чем могу помочь?"
                # French
                if any(word in query_lower for word in ["bonjour", "salut", "bonsoir"]):
                    return "Bonjour! Comment puis-je vous aider?"
                # Spanish
                if any(word in query_lower for word in ["hola", "buenos", "buenas"]):
                    return "¡Hola! ¿En qué puedo ayudarte?"
                # German
                if any(word in query_lower for word in ["hallo", "guten"]):
                    return "Hallo! Wie kann ich dir helfen?"
                # Default English
                return "Hello! How can I help you today?"

        # Very short queries that are likely greetings (expanded for multiple languages)
        short_greetings = {
            "ciao": "Ciao! Come posso aiutarti?",
            "salve": "Salve! Come posso aiutarti?",
            "hello": "Hello! How can I help you?",
            "hi": "Hi! How can I help you?",
            "hey": "Hey! How can I help you?",
            "привіт": "Привіт! Чим можу допомогти?",
            "привет": "Привет! Чем могу помочь?",
            "bonjour": "Bonjour! Comment puis-je vous aider?",
            "salut": "Salut! Comment puis-je t'aider?",
            "hola": "¡Hola! ¿En qué puedo ayudarte?",
            "hallo": "Hallo! Wie kann ich dir helfen?",
        }

        if query_lower in short_greetings:
            return short_greetings[query_lower]

        return None

    def check_casual_conversation(self, query: str) -> bool:
        """
        Detect if query is a casual/lifestyle question that doesn't need RAG tools.

        Returns True if the query is casual (restaurants, music, personal, etc.)
        and should be answered directly without using vector_search or other tools.

        Args:
            query: User query string

        Returns:
            True if casual conversation, False otherwise
        """
        query_lower = query.lower().strip()

        # Business keywords that require RAG (MULTILINGUAL)
        business_keywords = [
            # English
            "visa", "kitas", "kitap", "voa", "pt pma", "pt local", "pma", "kbli",
            "tax", "pajak", "pph", "ppn", "company", "business", "legal", "law",
            "regulation", "permit", "license", "contract", "notaris", "bank",
            "investment", "investor", "capital", "modal", "hukum", "peraturan",
            "undang", "izin", "akta", "npwp", "siup", "tdp", "nib", "oss",
            "immigration", "imigrasi", "sponsor", "rptka", "imta", "tenaga kerja",
            "how much", "quanto costa", "berapa", "pricing", "price", "harga",
            "deadline", "expire", "renewal", "extension", "perpanjang",
            # Team/organization keywords - require team_knowledge tool
            "ceo", "founder", "team", "tim", "anggota", "member", "staff",
            "chi è", "who is", "siapa", "direttore", "director", "manager",
            "bali zero", "zerosphere", "kintsugi",
            # Chinese (中文) business keywords
            "公司", "企业", "签证", "税", "投资", "资本", "商业", "法律",
            "注册", "许可", "印尼", "巴厘岛", "移民", "工作", "银行",
            "开公司", "办签证", "多少钱", "费用", "价格",
            # Arabic (العربية) business keywords
            "شركة", "تأشيرة", "ضريبة", "استثمار", "قانون", "عمل",
            # Russian/Ukrainian business keywords
            "компания", "виза", "налог", "инвестиция", "бизнес", "закон",
        ]

        # Check if it's a business question
        for keyword in business_keywords:
            if keyword in query_lower:
                return False

        # Casual conversation patterns (multilingual)
        casual_patterns = [
            # Food/restaurants (Italian, English, Indonesian, Ukrainian, Russian, French, Spanish, German)
            r"(ristorante|restaurant|makan|mangiare|food|cibo|warung|cafe|bar|dinner|lunch|breakfast|colazione|pranzo|cena)",
            r"(ресторан|їжа|кафе|обід|вечеря|сніданок)",  # Ukrainian
            r"(ресторан|еда|кафе|обед|ужин|завтрак)",  # Russian
            # Music
            r"(music|musica|lagu|song|cantante|singer|band|concert|spotify|playlist)",
            r"(музика|пісня|концерт|співак)",  # Ukrainian
            r"(музыка|песня|концерт|певец)",  # Russian
            # Weather/lifestyle
            r"(weather|cuaca|meteo|tempo|beach|pantai|spiaggia|surf|sunset|sunrise)",
            r"(погода|пляж|захід сонця|схід сонця)",  # Ukrainian
            r"(погода|пляж|закат|рассвет)",  # Russian
            # Personal questions (Italian, English, Indonesian)
            r"(come stai|how are you|apa kabar|gimana kabar|cosa fai|what do you do|che fai)",
            # Personal questions (Ukrainian, Russian, French, Spanish, German)
            r"(як справи|як ти|як ся маєш|що робиш)",  # Ukrainian
            r"(как дела|как ты|что делаешь)",  # Russian
            r"(comment ça va|comment vas-tu|ça va)",  # French
            r"(cómo estás|como estas|qué tal|que tal|qué haces|que haces)",  # Spanish (with and without accents)
            r"(wie geht's|wie geht es dir|was machst du)",  # German
            r"(preferisci|prefer|suka|like|favorite|favorito|best|migliore|consiglia|recommend)",
            # Hobbies/interests
            r"(hobby|hobi|sport|olahraga|travel|viaggio|movie|film|book|buku|libro)",
            r"(хобі|спорт|подорож|фільм|книга)",  # Ukrainian
            r"(хобби|спорт|путешествие|фильм|книга)",  # Russian
            # Places (non-business)
            r"(canggu|seminyak|ubud|uluwatu|kuta|sanur|nusa|gili)\s*(dinner|lunch|makan|restaurant|bar|cafe|beach|sunset)",
            # General chat
            r"(bali o jakarta|jakarta o bali|quale preferisci|which do you prefer)",
            r"(raccontami|tell me about yourself|parlami di te|cosa ti piace)",
            r"(розкажи про себе|що тобі подобається)",  # Ukrainian
            r"(расскажи о себе|что тебе нравится)",  # Russian
            r"(che musica|what music|che tipo di|what kind of)"
        ]

        for pattern in casual_patterns:
            if re.search(pattern, query_lower):
                return True

        # Check for non-Latin scripts (Chinese, Arabic, Cyrillic)
        # These scripts use fewer characters to express the same meaning,
        # so we should NOT use character count as a casual indicator
        has_chinese = any('\u4e00' <= c <= '\u9fff' for c in query)
        has_arabic = any('\u0600' <= c <= '\u06ff' for c in query)
        has_cyrillic = any('\u0400' <= c <= '\u04ff' for c in query)
        has_non_latin = has_chinese or has_arabic or has_cyrillic

        # For non-Latin scripts, don't use the short query heuristic
        # Instead, be conservative and use RAG (return False = not casual)
        if has_non_latin:
            logger.debug(f"[Non-Latin] Query contains non-Latin script, using RAG: {query[:30]}...")
            return False

        # UNIVERSAL CASUAL DETECTION (for Latin scripts only):
        # Short queries (< 60 chars) without business keywords are likely greetings/casual
        # This catches "Olá, como você está?" in Portuguese, etc.
        if len(query_lower) < 60:
            # Already checked no business keywords above, so this is casual
            logger.debug(f"[Casual] Short query without business keywords: {query_lower[:30]}...")
            return True

        return False

    def check_identity_questions(self, query: str) -> str | None:
        """Check for identity questions and return hardcoded responses.

        Detects common identity/meta questions using regex patterns and returns
        pre-written answers to avoid unnecessary model calls and ensure consistent
        brand messaging.

        Patterns Detected:
        1. Identity questions: "Who are you?", "Chi sei?", "What are you?"
           -> Returns: AI assistant introduction
        2. Company questions: "What does Bali Zero do?", "Cosa fa Bali Zero?"
           -> Returns: Company services overview

        Args:
            query: User query string (case-insensitive matching)

        Returns:
            Hardcoded response string if pattern matches, None otherwise

        Note:
            - Fast path: Avoids model inference for meta questions
            - Brand consistency: Ensures uniform messaging about identity
            - Multilingual: Supports Italian and English patterns
            - Performance: ~0.1ms vs ~500ms for model call

        Example:
            >>> builder = SystemPromptBuilder()
            >>> response = builder.check_identity_questions("Chi sei?")
            >>> print(response)
            Sono Zantara, l'assistente AI di Bali Zero...
            >>> response = builder.check_identity_questions("What is KITAS?")
            >>> print(response)  # None - not an identity question
        """
        query_lower = query.lower().strip()

        # Identity patterns
        identity_patterns = [
            r"^(chi|who|cosa|what)\s+(sei|are)\s*(you|tu)?\??$",
            r"^(chi|who)\s+(è|is)\s+(zantara)\??$",
        ]

        for pattern in identity_patterns:
            if re.search(pattern, query_lower):
                return (
                    "Sono Zantara, l'assistente AI di Bali Zero. "
                    "Ti aiuto con visa, business, investimenti e questioni legali in Indonesia. "
                    "Come posso esserti utile oggi?"
                )

        # Company patterns
        company_patterns = [
            r"^(cosa|what)\s+(fa|does)\s+(bali\s*zero|balizero)(\s+do)?\??$",
            r"^(parlami|tell\s+me)\s+(di|about)\s+(bali\s*zero|balizero)\??$",
        ]

        for pattern in company_patterns:
            if re.search(pattern, query_lower):
                return (
                    "Bali Zero è una consulenza specializzata in visa, KITAS, setup aziendale (PT PMA) "
                    "e questioni legali per stranieri in Indonesia. Offriamo servizi trasparenti, "
                    "veloci e affidabili per aiutarti a vivere e lavorare a Bali senza stress."
                )

        return None