# 🤖 Nzila AI Infrastructure

**Last Updated:** February 17, 2026  
**Owner:** CTO & AI Lead  
**Review Cycle:** Quarterly (Product + Legal + Ethics Council)

> **See also:** [PROGRAM_INDEX.md](PROGRAM_INDEX.md) — the adaptive AI governance
> program (principles, policy, charter, risk classification, regulation
> landscape, lifecycle gates, assurance, maturity, synthetic-data policy,
> rollout playbook). That program operationalizes — and sits above — the
> Companion Engine architecture documented below.

---

## 🎯 OVERVIEW

Nzila's AI infrastructure is **cross-platform, shared, and ethics-first**. The **Companion Engine** powers personalized AI experiences across 12+ platforms in healthtech, justice-equity, uniontech, and beyond.

This folder contains:
- ✅ **Architecture documentation** (Companion Engine, Prompt Library, Personality Graph)
- ✅ **Governance frameworks** (Ethical AI Charter, safety protocols, bias audits)
- ✅ **Integration guidelines** (how to embed Companion in new platforms)
- ✅ **IP protection protocols** (Prompt Library is $80K+ trade secret, HIGH protection)
- ✅ **Prompt engineering standards** (tone, voice, personalization rules)

---

## 📂 FOLDER STRUCTURE

```
ai/
├── README.md                           # This file
├── COMPANION_ENGINE_ARCHITECTURE.md    # Core AI engine specs
├── COMPANION_INTEGRATION_GUIDE.md      # How to add Companion to new platforms
├── PROMPT_ENGINEERING_STANDARDS.md     # Voice, tone, personalization rules
├── AI_GOVERNANCE_FRAMEWORK.md          # Ethics, safety, bias audits, compliance
├── COMPANION_PERSONALITY_GRAPH.md      # Tone adaptation algorithm (trade secret)
├── PROMPT_LIBRARY_OVERVIEW.md          # 200+ GPT-4 prompts (trade secret documentation)
├── AI_SAFETY_PROTOCOLS.md              # Incident response, fail-safes, testing
└── platform-integrations/              # Platform-specific Companion implementations
    ├── memora-companion.md             # Healthtech: cognitive wellness, dementia care
    ├── abr-companion.md                # Justice-equity: anti-racism learning coach
    ├── union-eyes-companion.md         # Uniontech: grievance guidance (future)
    ├── cora-companion.md               # AgTech: farm advisory (future)
    └── template-companion.md           # Template for new platform integrations
```

---

## 🧠 COMPANION ENGINE — CORE CAPABILITIES

The **Companion Engine** is Nzila's proprietary AI personalization layer, providing:

### **1. Adaptive Voice & Tone**
- **Warmth/Formality/Humor Spectrum**: Adapts based on user interaction patterns
- **Cultural Localization**: English/French with cultural tone adjustments
- **Context-Aware Prompts**: Different tone for cognitive wellness (warm, encouraging) vs. compliance training (professional, motivational)
- **IP**: Companion Personality Graph (🔴 HIGH protection trade secret, quarterly audit)

### **2. Prompt Library (200+ GPT-4 Prompts)**
- **Coverage**: Healthtech (dementia care, caregiver support), justice-equity (anti-racism coaching, case analysis), compliance (HR onboarding)
- **Structure**: Categorized by domain (healthtech/justice/union/ag), tone (warm/professional/motivational), user state (new/active/lapsed)
- **IP**: Companion Prompt Library v1 (🔴 HIGH protection trade secret, copyright registered Canada, $80K+ licensing value)
- **Access Control**: NDA-required, GitHub private repo with permission-based tagging, quarterly legal + ops audit

### **3. Behavior Change Architecture**
- **Nudge Engine**: Gentle, personalized nudges (not notifications spam)
- **Gamification Integration**: XP rewards, streaks, achievements (ABR 80%+ completion vs 25-30% industry avg)
- **Memory & Context**: User preferences, interaction history, caregiver/peer connections
- **Learning Loop**: Adjusts frequency, tone, timing based on engagement patterns (Phase 3-4 roadmap)

### **4. Multi-Platform Consistency**
- **Shared Backbone**: Single deployment (Azure OpenAI, pgVector, Drizzle ORM) powers all platforms
- **Domain-Specific Customization**: Platform-specific prompts layered on top of shared infrastructure
- **Standardized Integration**: Django 5 API endpoints + Next.js 14 client SDK
- **Observability**: Application Insights telemetry for prompt performance, user satisfaction, edge cases

---

## 🏗️ TECHNOLOGY STACK

| Component | Technology | Purpose |
|-----------|-----------|---------|
| **LLM Provider** | Azure OpenAI (GPT-4, GPT-4 Turbo) | Text generation, personalization, coaching |
| **Embeddings** | Azure OpenAI text-embedding-ada-002 | Semantic search, context retrieval |
| **Vector Database** | PostgreSQL pgVector | Prompt similarity, user history matching |
| **Prompt Management** | Django 5 Prompt Library (RLS policies) | Secure, versioned prompt storage |
| **Personalization Engine** | Django 5 Companion Personality Graph | Tone adaptation, user profiling |
| **Client SDK** | Next.js 14 Companion Client | Frontend integration (React hooks, streaming) |
| **Observability** | Azure Application Insights | Telemetry, error tracking, performance monitoring |
| **Compliance** | Azure AI Content Safety | Harmful content filtering, PII detection |

---

## 📊 PLATFORM COVERAGE

| Platform | Companion Status | Use Case | IP Protection |
|----------|-----------------|----------|---------------|
| **Memora** | ✅ Production (MVP) | Cognitive wellness companion (daily check-ins, game nudges, caregiver sync) | Prompt Library + Personality Graph |
| **ABR Insights** | ✅ Production | Anti-racism learning coach (200+ prompts, CanLII case analysis, personalized coaching) | Prompt Library (copyright registered Canada) |
| **CareAI** | ⏳ Beta | Caregiver support AI (respite planning, resource recommendations) | Prompt Library |
| **FamilySync** | ⏳ Roadmap 2027 | Family wellness coordinator (shared calendars, mood tracking, care coordination) | Prompt Library |
| **WellLoop** | ⏳ Roadmap 2027 | Chronic disease management companion (medication reminders, symptom tracking) | Prompt Library |
| **UnionEyes** | ⏳ Roadmap 2027 | Grievance guidance AI (contract interpretation, case outcome prediction) | Prompt Library |
| **CORA** | ⏳ Roadmap 2028 | Farm advisory AI (crop planning, market pricing, sustainability recommendations) | Prompt Library |
| **Companion API** | ⏳ Roadmap 2027-2028 | White-label Companion SDK (B2B offering for clinics, unions, cooperatives) | Full IP licensing |

**Impact**: 
- **8 platforms** sharing Companion infrastructure (4 production/beta, 4 roadmap)
- **$80K-$120K annual licensing potential** (Companion API B2B offering)
- **Network effects**: Each platform improves shared Prompt Library + Personality Graph

---

## 🔐 IP PROTECTION & CONFIDENTIALITY

### **Trade Secrets (🔴 HIGH Protection)**

1. **Companion Prompt Library v1** ($80K+ value)
   - 200+ GPT-4 prompts for personalized AI coaching
   - Categorized by domain (healthtech/justice/union/ag), tone, user state
   - Core to Companion UX differentiation vs. competitors (generic chatbots)
   - **Protection**: Copyright registered Canada, trade secret SOP documented, quarterly audit
   - **Access**: NDA-required, GitHub private repo with permission-based tagging
   - **Audit**: Quarterly legal + ops review

2. **Companion Personality Graph** ($60K+ value)
   - Tone adaptation algorithm: warmth/formality/humor spectrum
   - User profiling logic (interaction patterns → voice adjustments)
   - Differentiator vs. competitors (one-size-fits-all AI)
   - **Protection**: Trade secret (no patent planned, too easy to reverse-engineer), quarterly audit
   - **Access**: NDA-required, source code access restricted to CTO + AI Lead
   - **Audit**: Quarterly legal + ops review

### **Access Control Protocols**

| Asset | Access Level | Documentation | Audit Frequency |
|-------|--------------|---------------|-----------------|
| **Prompt Library** | CTO, AI Lead, Product Lead (NDA-required) | SOP: ai/PROMPT_LIBRARY_OVERVIEW.md | Quarterly |
| **Personality Graph Algorithm** | CTO, AI Lead only | SOP: ai/COMPANION_PERSONALITY_GRAPH.md | Quarterly |
| **Platform Integration Code** | Engineering team (GitHub private repo) | Public: Integration guides, Private: Prompt keys | Bi-annual |
| **Companion API Keys** | Per-platform basis (Azure Key Vault rotation) | Corporate IT security policy | Monthly |

---

## ⚖️ GOVERNANCE & ETHICS

Nzila's AI development follows the **Ethical AI Charter** (corporate/compliance/ethical-ai-charter.md) with:

### **1. Human Agency & Oversight**
- ✅ Companion **recommends, never enforces** (e.g., "Want to play a cognitive game?" not "Play now")
- ✅ **Interruptible & reversible** (users can disable/pause Companion anytime)
- ✅ **Human-in-the-loop** for sensitive workflows (caregiver alerts, mood summaries)

### **2. Privacy by Design**
- ✅ **Law 25 (Quebec), PIPEDA, GDPR, HIPAA** compliant
- ✅ **De-identified or synthetic data** for training (unless full consent)
- ✅ **AI Privacy Logbook** updated quarterly (clinical partners, privacy officers, researchers)

### **3. Fairness & Bias Mitigation**
- ✅ **Bias & Representativeness Reviews** before pilot deployment
- ✅ **Demographic edge-case testing** (synthetic personas for diverse populations)
- ✅ **72-hour patch requirement** for bias-related failures

### **4. Transparency & Explainability**
- ✅ **"Why this prompt?" tooltips** in UI (logic path visible to users)
- ✅ **Public Companion Design Sheet** (decision trees, learning loops documented)
- ✅ **Known Limitations Registry** (every AI system has documented edge cases)
- ✅ **Audit trail**: Every nudge/alert logged with timestamp, model version, user consent

### **5. Safety & Incident Response**
- ✅ **AI Governance Council** (CTO, Product, Legal, Ethics Advisor)
- ✅ **72-hour incident triage** (inaccurate nudge, improper flag, harmful content)
- ✅ **Fail-safes**: Companion defaults to neutral fallback tone if logic unclear
- ✅ **Azure AI Content Safety** integration (harmful content filtering, PII detection)

---

## 🧪 TESTING & QA

All Companion deployments follow **multi-tier AI QA protocol**:

| Test Type | Description | Frequency |
|-----------|-------------|-----------|
| **Functional QA** | Model behaves as expected across use cases | Every release |
| **Edge Simulation** | Rare/emotionally complex scenarios (e.g., user distress, unusual inputs) | Every release |
| **Regression Checks** | No unintended behavior in updates | Every release |
| **Bias Audits** | Demographic edge-case testing (synthetic personas) | Quarterly |
| **Tone Audits** | Caregiver feedback panels, clinical partner simulations | Bi-annual |
| **Prompt Performance** | User satisfaction surveys, A/B tests for new prompts | Monthly (active platforms) |

### **Testing Environments**
- **Synthetic Data Sandbox**: Simulated users, edge cases, stress tests (no real PII)
- **Pilot Environments**: Controlled rollouts with 10-50 users (consent-based)
- **Production Monitoring**: Application Insights telemetry (latency, errors, user satisfaction)

---

## 🚀 INTEGRATION WORKFLOW

**Adding Companion to a new platform (4-week timeline)**:

### **Week 1: Requirements & Design**
1. ✅ Define use case (cognitive wellness, learning coach, grievance guidance, farm advisory)
2. ✅ Identify tone profile (warm/professional/motivational, cultural localization)
3. ✅ Select/customize prompts from Prompt Library (or create new domain-specific prompts)
4. ✅ Design user flows (check-ins, nudges, memory sync, caregiver alerts)

### **Week 2: Backend Integration**
1. ✅ Deploy Companion Django 5 API endpoints (Azure Container Apps)
2. ✅ Configure pgVector for prompt similarity + user history
3. ✅ Set up Azure OpenAI API keys (per-platform quota management)
4. ✅ Implement Personality Graph logic (tone adaptation based on user profile)
5. ✅ Configure RLS policies (Row-Level Security for multi-tenant isolation)

### **Week 3: Frontend Integration**
1. ✅ Install Next.js 14 Companion Client SDK (React hooks for prompts, streaming)
2. ✅ Build UI components (chat interface, nudge cards, tooltips with explainability)
3. ✅ Implement consent flows (enable/disable Companion, pause notifications)
4. ✅ Integrate with platform-specific features (game nudges for Memora, case analysis for ABR)

### **Week 4: Testing & Launch**
1. ✅ Functional QA (expected behavior across use cases)
2. ✅ Edge simulation (rare scenarios, emotional complexity)
3. ✅ Pilot rollout (10-50 consented users)
4. ✅ Monitoring setup (Application Insights telemetry, user satisfaction surveys)
5. ✅ Production launch (gradual rollout, 25% → 50% → 100%)

**See**: `ai/COMPANION_INTEGRATION_GUIDE.md` for detailed step-by-step instructions

---

## 📈 SUCCESS METRICS

| Metric | Target | Current (2026) | Platform |
|--------|--------|----------------|----------|
| **User Engagement** | 60%+ weekly active users engage with Companion | 55% | Memora |
| **Completion Rate** | 70%+ complete Companion-suggested activities | 80%+ | ABR Insights (gamification) |
| **Satisfaction Score** | 4.5+/5 user satisfaction with Companion tone/helpfulness | 4.6/5 | Memora (pilot) |
| **Retention Lift** | +15-20% retention vs. non-Companion users | +18% | Memora |
| **Bias Incidents** | 0 confirmed bias/fairness incidents | 0 | All platforms |
| **Safety Incidents** | 0 harmful content incidents | 0 | All platforms |

---

## 🛠️ ROADMAP

### **2026 Q1-Q2** (Current)
- ✅ Memora Companion MVP (production)
- ✅ ABR Insights AI Coach (production, 200+ prompts)
- ⏳ CareAI Companion Beta (caregiver support)
- ⏳ Prompt Library v2 (expand to 300+ prompts, add union/ag domains)

### **2026 Q3-Q4**
- ⏳ UnionEyes Companion (grievance guidance, contract interpretation)
- ⏳ CORA Companion (farm advisory, crop planning, market pricing)
- ⏳ Companion Learning Loop (Phase 3: adaptive tone based on engagement)
- ⏳ Mood Detection (Phase 3: sentiment analysis, fatigue detection)

### **2027**
- ⏳ FamilySync Companion (family wellness coordinator)
- ⏳ WellLoop Companion (chronic disease management)
- ⏳ Companion API (B2B white-label SDK for clinics, unions, cooperatives)
- ⏳ Open-source SDKs with explainable Companion logic (post-patent filings)

---

## 📞 KEY CONTACTS

| Role | Name | Responsibility |
|------|------|----------------|
| **AI Lead** | TBD (CTO interim) | Companion Engine architecture, Prompt Library management |
| **Product Lead** | TBD | Platform integrations, user experience, tone audits |
| **Legal Counsel** | TBD | IP protection (trade secrets, copyrights), NDA enforcement |
| **Ethics Advisor** | TBD | AI Governance Council, bias audits, Ethical AI Charter compliance |
| **Clinical Partners** | Multiple (Memora pilots) | Caregiver feedback panels, clinical simulations |

---

## 📚 DOCUMENTATION INDEX

| Document | Purpose | Audience |
|----------|---------|----------|
| **COMPANION_ENGINE_ARCHITECTURE.md** | Technical specs (API endpoints, pgVector, Azure OpenAI integration) | Engineering |
| **COMPANION_INTEGRATION_GUIDE.md** | Step-by-step platform integration (week-by-week timeline) | Engineering + Product |
| **PROMPT_ENGINEERING_STANDARDS.md** | Voice, tone, personalization rules (how to write Companion prompts) | Product + Content |
| **AI_GOVERNANCE_FRAMEWORK.md** | Ethics, safety, bias audits, compliance (Ethical AI Charter implementation) | Legal + Product |
| **COMPANION_PERSONALITY_GRAPH.md** | Tone adaptation algorithm (🔴 trade secret, NDA-required) | CTO + AI Lead only |
| **PROMPT_LIBRARY_OVERVIEW.md** | 200+ GPT-4 prompts catalogue (🔴 trade secret, NDA-required) | CTO + AI Lead + Product |
| **AI_SAFETY_PROTOCOLS.md** | Incident response, fail-safes, testing protocols | Engineering + Product |
| **platform-integrations/** | Platform-specific Companion implementations (Memora, ABR, UnionEyes, CORA) | Engineering + Product |

---

## ✅ GETTING STARTED

**New to Companion?**
1. Read: `COMPANION_ENGINE_ARCHITECTURE.md` (understand core capabilities)
2. Read: `PROMPT_ENGINEERING_STANDARDS.md` (learn voice/tone rules)
3. Review: `platform-integrations/memora-companion.md` (reference implementation)
4. Follow: `COMPANION_INTEGRATION_GUIDE.md` (integrate Companion into your platform)

**Adding new prompts?**
1. Review existing prompts: `PROMPT_LIBRARY_OVERVIEW.md` (🔴 NDA-required)
2. Follow tone guidelines: `PROMPT_ENGINEERING_STANDARDS.md`
3. Submit PR with: Domain category, tone profile, user state, A/B test plan
4. QA review: CTO + Product Lead approval required

**Governance questions?**
- Ethical concerns: AI Governance Council (CTO + Legal + Ethics Advisor)
- Bias/safety incidents: Log in `AI Safety Incident Tracker` (72-hour triage SLA)
- Privacy/compliance: Legal Counsel + corporate/compliance/ethical-ai-charter.md

---

**© 2026 Nzila Ventures. Confidential & Proprietary.**  
**Companion Prompt Library & Personality Graph: Trade Secrets (🔴 HIGH Protection)**  
*Last Updated: February 17, 2026*
