Vina: AI-Powered Adaptive Learning Platform - PRD & Implementation Plan
Version: 1.0
Last Updated: February 4, 2026
Project Status: Phase 1 Complete, Phase 2 In Progress
Target: Commit To Change: An AI Agents Hackathon

Table of Contents

Product Overview
Architecture Overview
Completed Components (Phase 1)
Current Status & Blockers
Remaining Implementation (Phase 2-4)
Detailed Step-by-Step Implementation Plan
Pre-Generation Strategy
Testing & Validation
Deployment Plan
Success Criteria


Product Overview
What is Vina?
Vina is a personalized, adaptive video learning platform that helps professionals upskill in AI technologies. The platform dynamically adjusts content difficulty and examples based on:

Profession & Industry (e.g., Clinical Researcher in Pharma)
Real-time feedback via an "Adapt" button during lessons
Quiz performance after each lesson

Core Innovation
Unlike traditional e-learning platforms, Vina uses a three-agent system (Generator → Reviewer → Rewriter) to ensure high-quality, personalized lessons that adapt in real-time to learner needs.
Target Users
Professionals across 4 professions × 3 industries each = 12 learner personas:

Clinical Researcher (Pharma/Biotech, Academic Research, Medical Devices)
HR Manager (Tech Company, Financial Services, Manufacturing)
Project Manager (Software/Tech, Construction, Healthcare)
Marketing Manager (E-Commerce, B2B SaaS, Consumer Goods)

Hackathon Scope
Course: LLM Foundations (17 micro-lessons, ~50 minutes total)
Demo Lessons: 5 lessons pre-generated for 12 personas (60 videos)
Format: Vertical 9:16 video (mobile-first, TikTok-style)
Adaptations: 4 options (Simplify this, Get to the point, I know this already, More examples)

Architecture Overview
System Components
┌─────────────────────────────────────────────────────────────┐
│                         Frontend                            │
│  Next.js + Tailwind CSS (Deployed on Vercel)              │
│  - Vertical video player                                   │
│  - Adapt button overlay (4 options)                        │
│  - Quiz interface                                          │
│  - Session management (localStorage)                       │
└─────────────────────────────────────────────────────────────┘
                              │
                              ▼
┌─────────────────────────────────────────────────────────────┐
│                         Backend API                         │
│  FastAPI (Python) - Deployed on Railway                    │
│  - Profile generation endpoints                            │
│  - Lesson retrieval endpoints                              │
│  - Adaptation endpoints                                    │
│  - Quiz endpoints                                          │
└─────────────────────────────────────────────────────────────┘
                              │
                              ▼
┌─────────────────────────────────────────────────────────────┐
│                    Core Services Layer                      │
│  - ProfileBuilder: Generate user profiles                  │
│  - CourseLoader: Load configurations                       │
│  - LessonGenerator: Generate lessons (3-agent pipeline)    │
│  - QuizGenerator: Generate MCQ quizzes                     │
│  - VideoRenderer: Create MP4 from slides + TTS             │
└─────────────────────────────────────────────────────────────┘
                              │
                              ▼
┌─────────────────────────────────────────────────────────────┐
│                    Integration Layer                        │
│  - LLM Client (llmlite): Multi-provider support           │
│  - Database (SQLite + SQLModel)                            │
│  - Video Storage (Cloudinary)                              │
│  - TTS (ElevenLabs)                                        │
│  - Observability (Opik)                                    │
└─────────────────────────────────────────────────────────────┘
                              │
                              ▼
┌─────────────────────────────────────────────────────────────┐
│                    Configuration Layer                      │
│  - Global Course Config (course_config_global.json)        │
│  - Course-Specific Config (llm_foundations.json)           │
│  - User Profile Prompts (user_profile_gen.md)             │
│  - Lesson Generation Prompts (TBD)                         │
└─────────────────────────────────────────────────────────────┘
Data Flow: Lesson Generation
User Request (profession, industry, lesson_id, difficulty)
    │
    ▼
Load User Profile (from DB or generate)
    │
    ▼
Load Course Config + Lesson Spec
    │
    ▼
Check Cache (lesson_id + profession + industry + difficulty)
    │
    ├─ HIT → Serve video URL instantly
    │
    └─ MISS → Generate lesson
         │
         ├─ Generator Agent: Create lesson content
         │
         ├─ Reviewer Agent: Evaluate quality/fit
         │
         ├─ Rewriter Agent (if needed): Fix issues
         │
         ├─ Render Video (MoviePy + ElevenLabs)
         │
         ├─ Upload to Cloudinary
         │
         ├─ Cache video URL
         │
         └─ Return video URL
Adaptation Flow
User clicks "Simplify this" during Lesson 5
    │
    ▼
Calculate new difficulty (current - 2 = difficulty 1)
    │
    ▼
Check cache (l05 + profession + industry + difficulty 1)
    │
    ├─ HIT → Serve cached video
    │
    └─ MISS → Generate with difficulty 1 knobs
         │
         └─ Cache and serve
    │
    ▼
Update Learner State (current_difficulty = 1)
    │
    ▼
Next lesson (L06) starts at difficulty 1

Completed Components (Phase 1)
✅ 1. Project Structure & Configuration
Status: Complete
Files Created:

src/vina_backend/ (package structure initialized with uv init --package vina_backend)
src/vina_backend/core/config.py (Pydantic Settings with multi-provider LLM config)
.env.example (template with all required API keys)
.gitignore (excludes .env, *.db, cache/)
Folder structure: api/routers, services, domain/{schemas,constants}, integrations/{db,llm,cloudinary,opik}, prompts/{profile,lesson,quiz}, scripts/, tests/, data/, cache/{videos,audio}

Key Features:

Multi-provider LLM support (Anthropic, OpenAI, Gemini)
get_active_api_key() method validates correct key for active provider
Environment-based configuration with validation

Location: /home/claude/vina_backend/

✅ 2. LLM Integration
Status: Complete
Files Created:

src/vina_backend/integrations/llm/client.py (llmlite wrapper)

Key Features:

generate() method for text generation
generate_json() method with markdown fence cleanup
Provider-agnostic (switches via config, no code changes)
Automatic fallback on 503 errors (tries alternative models)
Temperature handling for different providers (Gemini 3 requires temp=1.0)
Model validation (warns if model doesn't match provider)
Global client instance with lazy initialization

Supported Providers:

Anthropic: claude-sonnet-4-20250514, claude-opus-4-20241213
OpenAI: gpt-4o, gpt-4o-mini
Gemini: gemini-3-flash-preview, gemini-2.5-flash


✅ 3. User Profile Generation
Status: Complete and Tested
Files Created:

src/vina_backend/prompts/profile/user_profile_gen.md (Markdown prompt template)
src/vina_backend/domain/schemas/profile.py (Pydantic models: UserProfileData, UserProfileRequest, UserProfileResponse)
src/vina_backend/services/profile_builder.py (generate_user_profile, get_or_create_user_profile, validate_profile)
src/vina_backend/integrations/db/repositories/profile_repository.py (ProfileRepository with get, save, delete)
scripts/test_profile_gen.py (validation script)

Profile Schema (UserProfileData):
python- profession: str
- industry: str
- experience_level: Literal["Beginner", "Intermediate", "Advanced"]
- daily_responsibilities: List[str]
- pain_points: List[str]
- typical_outputs: List[str]
- technical_comfort_level: Literal["Low", "Medium", "High"]
- learning_style_notes: str
- professional_goals: List[str]
- safety_priorities: List[str]  # NEW: Critical safety/ethical considerations
- high_stakes_areas: List[str]  # NEW: Work outputs where errors are catastrophic
How It Works:

User inputs: profession, industry, experience_level
Prompt is formatted with inputs
LLM generates comprehensive profile as JSON
Validated with Pydantic
Saved to database for reuse
Retrieved on subsequent requests (no re-generation)

Testing: Successfully generates profiles for all 4 professions across 3 industries each

✅ 4. Global Course Configuration
Status: Complete
Files Created:

src/vina_backend/domain/constants/course_config_global.json

Contains:

global_difficulty_framework: 3 levels (1=Guided, 3=Practical, 5=Direct) with concrete delivery metrics

words_per_slide, analogies_per_concept, examples_per_concept
jargon_density, sentence_structure, slide_count
Content scope (what to include/exclude at each level)


global_adaptation_rules: 4 adaptation types

simplify_this (→ difficulty 1)
get_to_the_point (→ difficulty 5)
i_know_this_already (→ checkpoint quiz + skip)
more_examples (→ pre-rendered examples)


global_content_guidelines: Tone, structure, example types, language to avoid
global_quiz_framework: MCQ structure, coverage rules, feedback rules
global_safety_rules: Domain-agnostic safety principles
cross_lesson_coherence_rules: How to reference previous lessons
metadata_tracking_for_observability: What to log for Opik

Key Design: Fully domain-agnostic—works for any course on any topic, not just LLM courses

✅ 5. Course-Specific Configuration (LLM Foundations)
Status: Complete
Files Created:

src/vina_backend/domain/constants/courses/llm_foundations.json

Contains:

course_context: Position in series, prerequisites, scope boundaries
pedagogical_progression: 3 stages (Foundations, Application, Mastery) with teaching approaches
course_specific_safety_rules: LLM-specific safety guidance (hallucinations, bias, human-in-the-loop)
cross_lesson_coherence_rules: How lessons reference each other
lessons: 17 micro-lessons (flat structure, 2-4 min each)

Lesson Structure:
json{
  "lesson_id": "l01_what_llms_are",
  "lesson_number": 1,
  "lesson_name": "What LLMs Are",
  "topic_group": "The Foundations",
  "estimated_duration_minutes": 3,
  "prerequisites": [],
  "what_learners_will_understand": [...],
  "misconceptions_to_address": [...],
  "content_constraints": {
    "avoid": [...],
    "emphasize": [...]
  },
  "references_previous_lessons": {...}
}
Topics Covered:

The Foundations (L01-L03): What LLMs are, tokens/context windows, output variation
Capabilities & Risks (L04-L07): Where LLMs excel, hallucinations, bias, safe use
Business Use Cases (L08-L10): High-ROI tasks, good vs poor fit, workflow design
The LLM Landscape (L11-L13): Cloud APIs, self-hosted, choosing setup
Prompting Skills (L14-L17): Prompt anatomy, few-shot, iteration, role-specific


✅ 6. Domain Constants & Enums
Status: Complete
Files Created:

src/vina_backend/domain/constants/enums.py

Contains:

SUPPORTED_PROFESSIONS: List of 4 professions
INDUSTRIES_BY_PROFESSION: Mapping of 3 industries per profession
Enums: LLMProvider, ExperienceLevel, TechnicalComfort

Usage:
pythonfrom vina_backend.domain.constants.enums import SUPPORTED_PROFESSIONS

for profession in SUPPORTED_PROFESSIONS:
    for industry in INDUSTRIES_BY_PROFESSION[profession]:
        # Generate profile for this combo

✅ 7. Database Setup
Status: Partially Complete
Files Created:

src/vina_backend/integrations/db/engine.py (SQLAlchemy engine)
src/vina_backend/integrations/db/session.py (session generator)
src/vina_backend/integrations/db/models/user.py (UserProfile model)
src/vina_backend/integrations/db/repositories/profile_repository.py (ProfileRepository)
scripts/init_db.py (database initialization script)

Database Models:

✅ UserProfile (complete with safety_priorities and high_stakes_areas)
⚠️ LearnerSession (pending)
⚠️ Lesson (pending)
⚠️ QuizAttempt (pending)

Schema:
sqlCREATE TABLE user_profiles (
  id INTEGER PRIMARY KEY,
  profession TEXT,
  industry TEXT,
  experience_level TEXT,
  daily_responsibilities JSON,
  pain_points JSON,
  typical_outputs JSON,
  professional_goals JSON,
  technical_comfort_level TEXT,
  learning_style_notes TEXT,
  safety_priorities JSON,
  high_stakes_areas JSON,
  created_at TEXT,
  updated_at TEXT
);
CREATE INDEX idx_profession ON user_profiles(profession, industry, experience_level);

Current Status & Blockers
🟡 Phase 1.5: Missing Components Before Learner State
BLOCKER: These 3 components must be completed before implementing Learner State.
1. Course Loader Service (⚠️ CRITICAL)
File: src/vina_backend/services/course_loader.py
Status: Not Created
Why Needed: Learner State needs to know total lessons, lesson specs, difficulty knobs
Functions Required:

load_global_config() → Dict
load_course_config(course_id) → Dict
get_lesson_config(course_id, lesson_id) → Dict
get_difficulty_knobs(difficulty_level) → Dict
get_adaptation_rules(adaptation_type) → Dict
get_pedagogical_stage(course_id, lesson_id) → Dict

Estimated Time: 15 minutes
2. UserProfile Database Model (⚠️ CRITICAL)
File: src/vina_backend/integrations/db/models/user.py
Status: Partially Complete (needs safety fields)
Why Needed: Database needs model to create table, repository already references it
Missing: Ensure safety_priorities and high_stakes_areas are in the SQLModel
Estimated Time: 5 minutes
3. Validation Script (⚠️ RECOMMENDED)
File: scripts/validate_setup.py
Status: Not Created
Why Needed: Ensure Phase 1 is fully functional before moving to Phase 2
Tests:

Global config loads correctly
Course config loads correctly
Lesson config retrieval works
Difficulty knobs load
Pedagogical stage detection works
Profile generation works with safety fields

Estimated Time: 10 minutes

Remaining Implementation (Phase 2-4)
Phase 2: Core Generation Pipeline (Priority: CRITICAL)
2.1 Learner State Management
Estimated Time: 2-3 hours
Files to Create:

src/vina_backend/domain/schemas/learner_state.py (Pydantic models)
src/vina_backend/integrations/db/models/session.py (SQLModel)
src/vina_backend/integrations/db/repositories/session_repository.py
src/vina_backend/services/learner_state_manager.py

Schema:
pythonclass LearnerState(BaseModel):
    session_id: str
    user_profile_id: int
    course_id: str
    current_lesson_index: int
    lesson_difficulty_history: Dict[str, int]  # {lesson_id: difficulty_level}
    current_difficulty: int
    completed_lessons: List[str]
    quiz_scores: Dict[str, int]  # {lesson_id: score_out_of_3}
    adaptation_count: int
    created_at: datetime
    updated_at: datetime
Functions Required:

create_session(user_profile, course_id) → LearnerState
get_session(session_id) → LearnerState
update_difficulty(session_id, new_difficulty) → LearnerState
mark_lesson_complete(session_id, lesson_id, quiz_score) → LearnerState
get_next_lesson(session_id) → str (lesson_id)
record_adaptation(session_id, lesson_id, adaptation_type) → void

Testing:

Create session for Clinical Researcher
Simulate lesson completion with quiz scores
Verify difficulty adjusts correctly (3/3 → +1, 0-1/3 → -1, 2/3 → maintain)
Verify adaptation tracking


2.2 Lesson Generation Prompts & Architecture
**Estimated Time:** 3-4 hours  
**Status:** Enhanced with graduated approval, caching, and retry logic

### Design Decisions & Enhancements

**Key Improvements Over Initial Plan:**
1. **Graduated Approval** - Quality scores (0-10) instead of binary pass/fail
2. **Caching Layer** - Avoid regenerating identical lessons (70-90% cost savings)
3. **Retry Limits** - Max 2 iterations to prevent infinite loops
4. **JSON Validation** - Schema validation before reviewer step
5. **Dynamic Slide Count** - Pulled from difficulty knobs (not hardcoded 3-6)
6. **Enhanced Safety Checks** - Reviewer validates against `high_stakes_areas`
7. **Constraint Preservation** - Rewriter receives original constraints to prevent violations

### Files to Create

- `src/vina_backend/prompts/lesson/generator_prompt.md` (Jinja2 template)
- `src/vina_backend/prompts/lesson/reviewer_prompt.md` (Jinja2 template)
- `src/vina_backend/prompts/lesson/rewriter_prompt.md` (Jinja2 template)
- `src/vina_backend/services/lesson_cache.py` (Caching layer)
- `src/vina_backend/domain/schemas/lesson.py` (Pydantic models for validation)

---

### Generator Prompt Structure

```markdown
You are an expert instructional designer creating personalized micro-lessons.

LEARNER CONTEXT:
- Profession: {profession}
- Industry: {industry}
- Typical Outputs: {typical_outputs}
- Safety Priorities: {safety_priorities}
- High-Stakes Areas: {high_stakes_areas}
- Technical Comfort: {technical_comfort_level}

LESSON TO CREATE:
- Lesson: {lesson_name}
- Topic Group: {topic_group}
- Duration: {estimated_duration_minutes} minutes
- Learning Objectives: {what_learners_will_understand}
- Misconceptions to Address: {misconceptions_to_address}

DIFFICULTY LEVEL: {difficulty_level} ({difficulty_label})
Target Slide Count: {slide_count}  <!-- PULLED FROM DIFFICULTY KNOBS -->
Words Per Slide: {words_per_slide}
Analogies Per Concept: {analogies_per_concept}
Examples Per Concept: {examples_per_concept}
Jargon Density: {jargon_density}
Sentence Structure: {sentence_structure}

PEDAGOGICAL STAGE: {stage_name}
Teaching Approach: {teaching_approach}
Focus: {stage_focus}

COURSE-SPECIFIC SAFETY:
{course_specific_safety_rules}

CONTENT CONSTRAINTS:
- Avoid: {content_constraints.avoid}
- Emphasize: {content_constraints.emphasize}

**CRITICAL SAFETY RULE:**
Do NOT suggest automation or LLM use for these high-stakes areas without explicit human oversight:
{high_stakes_areas}

OUTPUT FORMAT:
Generate a lesson with {slide_count} slides in JSON:
{
  "lesson_title": "...",
  "slides": [
    {
      "slide_number": 1,
      "slide_type": "hook|concept|example|connection",
      "heading": "...",
      "content": ["bullet 1", "bullet 2", "bullet 3"],
      "speaker_notes": "What to say when presenting this slide"
    }
  ],
  "references_to_previous_lessons": "..."
}
```

---

### Reviewer Prompt Structure (ENHANCED)

```markdown
You are a quality assurance expert evaluating lesson content.

LESSON TO REVIEW:
{generated_lesson_json}

ORIGINAL CONSTRAINTS (for reference):
- Difficulty Level: {difficulty_level} ({difficulty_label})
- Target Slide Count: {slide_count}
- Safety Priorities: {safety_priorities}
- High-Stakes Areas: {high_stakes_areas}
- Content Constraints: {content_constraints}

EVALUATION CRITERIA:
1. **Learning Objectives**: Does it cover all objectives from the lesson spec?
2. **Misconceptions**: Does it address all listed misconceptions?
3. **Difficulty Alignment**: Is the complexity appropriate for difficulty {difficulty_level}?
   - Check: slide count, words per slide, analogies, jargon density
4. **Profession-Specific Examples**: Are examples tied to {profession} and {typical_outputs}?
5. **Content Constraints**: Does it avoid forbidden topics and emphasize required ones?
6. **Duration**: Is it within {estimated_duration_minutes} minutes?
7. **Safety Priorities**: Does it respect {safety_priorities}?
8. **High-Stakes Areas**: Does it avoid suggesting automation for {high_stakes_areas} without human oversight?
9. **Coherence**: Do slides flow logically (hook → concept → example → connection)?

OUTPUT (JSON):
{
  "quality_score": 8.5,  // 0-10 scale
  "approval_status": "approved" | "approved_with_minor_fixes" | "needs_revision",
  "critical_issues": [
    "Critical issue 1 (MUST fix): ..."
  ],
  "minor_issues": [
    "Minor issue 1 (nice to fix): ..."
  ],
  "suggested_fixes": [
    "Fix 1: ...",
    "Fix 2: ..."
  ],
  "strengths": [
    "What the lesson does well..."
  ]
}

**Approval Logic:**
- `approved`: quality_score >= 8 AND no critical_issues
- `approved_with_minor_fixes`: quality_score >= 7 AND no critical_issues
- `needs_revision`: quality_score < 7 OR critical_issues exist
```

---

### Rewriter Prompt Structure (ENHANCED)

```markdown
You are fixing a lesson based on reviewer feedback.

ORIGINAL LESSON:
{generated_lesson_json}

REVIEWER FEEDBACK:
Quality Score: {quality_score}/10
Approval Status: {approval_status}

Critical Issues (MUST FIX):
{critical_issues}

Minor Issues (if time permits):
{minor_issues}

Suggested Fixes:
{suggested_fixes}

ORIGINAL CONSTRAINTS (DO NOT VIOLATE THESE):
- Difficulty Level: {difficulty_level} ({difficulty_label})
- Target Slide Count: {slide_count}
- Safety Priorities: {safety_priorities}
- High-Stakes Areas: {high_stakes_areas}
- Content Constraints: {content_constraints}
- Learning Objectives: {what_learners_will_understand}
- Misconceptions to Address: {misconceptions_to_address}

**INSTRUCTIONS:**
1. Fix ALL critical issues
2. Fix minor issues if possible without violating constraints
3. Preserve what the reviewer praised (see "strengths")
4. Return the corrected lesson in the SAME JSON format

OUTPUT (JSON):
{
  "lesson_title": "...",
  "slides": [...],
  "references_to_previous_lessons": "..."
}
```

---

### Caching Strategy

**Cache Key:**
```python
cache_key = f"{course_id}:{lesson_id}:d{difficulty}:{profile_hash}"
# Example: "c_llm_foundations:l01_what_llms_are:d3:a3f2b1c"
```

**Profile Hash:**
```python
profile_hash = hashlib.md5(
    f"{profession}:{industry}:{experience_level}".encode()
).hexdigest()[:7]
```

**Cache Storage:**
- **Database Table:** `lesson_cache` (lesson_id, cache_key, lesson_json, created_at)
- **Invalidation:** Only regenerate if:
  - Cache miss
  - Course config updated (check `course_config.updated_at`)
  - User explicitly requests adaptation ("Simplify this", "Get to the point")

**Expected Impact:**
- First-time learners: Full generation (3-4 LLM calls)
- Repeat learners (same profile): Cache hit (0 LLM calls)
- Cost reduction: 70-90% for mature courses

---

### Generation Pipeline (Revised Architecture)

```python
def generate_lesson(
    lesson_id: str,
    course_id: str,
    user_profile: UserProfileData,
    difficulty_level: int,
    adaptation_context: Optional[str] = None  # "simplify_this", "get_to_the_point", etc.
) -> Dict:
    """
    Generate lesson with caching, validation, and retry logic.
    
    Returns:
        {
            "lesson_title": str,
            "slides": List[Dict],
            "references_to_previous_lessons": str,
            "generation_metadata": {
                "cache_hit": bool,
                "llm_model": str,
                "generation_time_seconds": float,
                "review_passed_first_time": bool,
                "rewrite_count": int,
                "quality_score": float
            }
        }
    """
    
    # 1. Check cache (skip if adaptation requested)
    if not adaptation_context:
        cached_lesson = lesson_cache.get(course_id, lesson_id, difficulty_level, user_profile)
        if cached_lesson:
            return {**cached_lesson, "generation_metadata": {"cache_hit": True}}
    
    # 2. Load context
    course_config = load_course_config(course_id)
    lesson_spec = get_lesson_config(course_id, lesson_id)
    difficulty_knobs = get_difficulty_knobs(difficulty_level)
    pedagogical_stage = get_pedagogical_stage(course_id, lesson_id)
    
    # 3. Generate initial lesson
    generator_prompt = format_generator_prompt(
        lesson_spec, user_profile, difficulty_level, difficulty_knobs, pedagogical_stage, course_config
    )
    
    max_retries = 2
    for attempt in range(max_retries):
        try:
            lesson_json = llm_client.generate_json(generator_prompt)
            
            # 4. Validate JSON schema
            validated_lesson = LessonSchema(**lesson_json)  # Pydantic validation
            break
        except (JSONDecodeError, ValidationError) as e:
            if attempt == max_retries - 1:
                logger.error(f"Failed to generate valid lesson after {max_retries} attempts")
                return fallback_lesson(lesson_id)  # Return generic lesson
            continue
    
    # 5. Review lesson
    reviewer_prompt = format_reviewer_prompt(lesson_json, lesson_spec, user_profile, difficulty_knobs)
    review_result = llm_client.generate_json(reviewer_prompt)
    
    rewrite_count = 0
    
    # 6. Rewrite if needed (max 1 rewrite)
    if review_result["approval_status"] == "needs_revision" and rewrite_count < 1:
        rewriter_prompt = format_rewriter_prompt(
            lesson_json, review_result, lesson_spec, difficulty_knobs, user_profile
        )
        lesson_json = llm_client.generate_json(rewriter_prompt)
        rewrite_count += 1
        
        # 7. Re-review
        review_result = llm_client.generate_json(
            format_reviewer_prompt(lesson_json, lesson_spec, user_profile, difficulty_knobs)
        )
    
    # 8. Cache if approved
    if review_result["approval_status"] in ["approved", "approved_with_minor_fixes"]:
        lesson_cache.set(course_id, lesson_id, difficulty_level, user_profile, lesson_json)
    
    # 9. Return with metadata
    return {
        **lesson_json,
        "generation_metadata": {
            "cache_hit": False,
            "llm_model": llm_client.model,
            "review_passed_first_time": rewrite_count == 0,
            "rewrite_count": rewrite_count,
            "quality_score": review_result["quality_score"]
        }
    }
```

---

### Testing Checklist

- [ ] Generate L01 for Clinical Researcher at difficulty 3
- [ ] Verify slide count matches difficulty knobs (4-5 slides for d3)
- [ ] Verify profession-specific examples present
- [ ] Verify all learning objectives covered
- [ ] Test cache: regenerate same lesson → should return cached version
- [ ] Test adaptation: regenerate at difficulty 1 → verify 5-6 slides and more analogies
- [ ] Test rewrite: inject failing review → verify rewriter fixes issues
- [ ] Test fallback: simulate JSON parsing failure → verify generic lesson returned
- [ ] Test safety: verify high-stakes areas not suggested for automation

2.3 Lesson Generation Service
Estimated Time: 3-4 hours
Files to Create:

src/vina_backend/services/lesson_generator.py

Functions Required:
pythondef generate_lesson(
    lesson_spec: Dict,
    user_profile: UserProfileData,
    difficulty_level: int,
    course_config: Dict,
    adaptation_context: Optional[str] = None
) -> Dict:
    """
    Generate a lesson using the 3-agent pipeline.
    
    Returns:
        {
            "lesson_title": str,
            "slides": List[Dict],
            "references_to_previous_lessons": str,
            "generation_metadata": {
                "llm_model": str,
                "generation_time_seconds": float,
                "review_passed_first_time": bool,
                "rewrite_count": int
            }
        }
    """
    # 1. Format generator prompt
    generator_prompt = format_generator_prompt(...)
    
    # 2. Generate initial lesson
    lesson_json = llm_client.generate_json(generator_prompt)
    
    # 3. Review lesson
    reviewer_prompt = format_reviewer_prompt(lesson_json, ...)
    review_result = llm_client.generate_json(reviewer_prompt)
    
    # 4. Rewrite if needed (max 2 attempts)
    if not review_result["approved"]:
        rewriter_prompt = format_rewriter_prompt(lesson_json, review_result)
        lesson_json = llm_client.generate_json(rewriter_prompt)
    
    return lesson_json
Testing:

Generate L01 for Clinical Researcher at difficulty 3
Verify lesson has 4-5 slides (per difficulty 3 metrics)
Verify profession-specific examples present
Verify all learning objectives covered
Test adaptation: regenerate at difficulty 1, verify 5-6 slides and more analogies


2.4 Quiz Generation
Estimated Time: 2-3 hours
Files to Create:

src/vina_backend/prompts/quiz/quiz_gen_prompt.md
src/vina_backend/services/quiz_generator.py
src/vina_backend/domain/schemas/quiz.py

Quiz Schema:
pythonclass QuizQuestion(BaseModel):
    question_number: int
    question_text: str
    options: List[str]  # 4 options: A, B, C, D
    correct_answer: str  # "A", "B", "C", or "D"
    explanation: str
    objective_id: str  # Which learning objective this tests

class Quiz(BaseModel):
    lesson_id: str
    questions: List[QuizQuestion]  # Always 3 questions
    pass_threshold: int = 2
Quiz Generation Prompt:
markdownGenerate 3 multiple-choice questions testing this lesson's learning objectives.

LESSON CONTEXT:
- Lesson: {lesson_name}
- Learning Objectives: {what_learners_will_understand}

LEARNER CONTEXT:
- Profession: {profession}
- Industry: {industry}
- Typical Outputs: {typical_outputs}

REQUIREMENTS:
- Each question tests a different learning objective
- At least one question uses a scenario from the learner's industry
- All 4 options should be plausible (no obviously wrong choices)
- Questions test application, not just recall

OUTPUT FORMAT:
{
  "questions": [
    {
      "question_number": 1,
      "question_text": "...",
      "options": ["A) ...", "B) ...", "C) ...", "D) ..."],
      "correct_answer": "B",
      "explanation": "...",
      "objective_id": "objective_1"
    }
  ]
}
Functions Required:
pythondef generate_quiz(
    lesson_id: str,
    lesson_spec: Dict,
    user_profile: UserProfileData
) -> Quiz:
    """Generate 3 MCQ questions for a lesson."""
    pass

def evaluate_quiz(
    quiz: Quiz,
    user_answers: List[str]
) -> Tuple[int, List[bool]]:
    """
    Evaluate user's quiz answers.
    
    Returns:
        (score, correctness_per_question)
    """
    pass

Phase 3: Video Generation Pipeline (Priority: HIGH)
3.1 Slide Rendering
Estimated Time: 3-4 hours
Files to Create:

src/vina_backend/services/slide_renderer.py
src/vina_backend/utils/image_utils.py

Technology: Pillow (PIL)
Slide Template:

Canvas: 1080×1920 (9:16 vertical)
Background: Gradient or solid color
Heading: Top 20%, bold, large font
Content: Middle 60%, bullet points with icons
Footer: Bottom 20%, lesson progress indicator

Functions Required:
pythondef render_slide(
    slide_data: Dict,
    slide_number: int,
    total_slides: int,
    output_path: Path
) -> Path:
    """
    Render a single slide to PNG.
    
    Args:
        slide_data: {heading, content, slide_type}
        slide_number: Current slide (1-indexed)
        total_slides: Total slides in lesson
        output_path: Where to save PNG
    
    Returns:
        Path to rendered PNG
    """
    # Create canvas
    img = Image.new('RGB', (1080, 1920), color='#1a1a2e')
    draw = ImageDraw.Draw(img)
    
    # Add heading
    # Add bullet points
    # Add progress indicator
    # Add branding/watermark
    
    img.save(output_path)
    return output_path

def render_lesson_slides(
    lesson_json: Dict,
    output_dir: Path
) -> List[Path]:
    """Render all slides in a lesson."""
    slides = []
    for i, slide_data in enumerate(lesson_json["slides"], 1):
        slide_path = render_slide(
            slide_data,
            i,
            len(lesson_json["slides"]),
            output_dir / f"slide_{i:02d}.png"
        )
        slides.append(slide_path)
    return slides
Testing:

Render sample lesson with 5 slides
Verify layout (heading, bullets, progress indicator)
Verify text wrapping (no overflow)
Verify readability on mobile screen


3.2 Text-to-Speech (TTS)
Estimated Time: 2 hours
Files to Create:

src/vina_backend/integrations/elevenlabs/tts_client.py

Technology: ElevenLabs API
Voice Selection:

Professional, clear, moderate pace
Gender-neutral or matched to target audience preference
Consistent voice across all lessons

Functions Required:
pythondef generate_audio_for_slide(
    speaker_notes: str,
    output_path: Path,
    voice_id: str = "default"
) -> Path:
    """
    Generate audio for a single slide.
    
    Args:
        speaker_notes: Text to speak
        output_path: Where to save MP3
        voice_id: ElevenLabs voice ID
    
    Returns:
        Path to generated MP3
    """
    response = elevenlabs.generate(
        text=speaker_notes,
        voice=voice_id,
        model="eleven_monolingual_v1"
    )
    
    with open(output_path, 'wb') as f:
        f.write(response)
    
    return output_path

def generate_lesson_audio(
    lesson_json: Dict,
    output_dir: Path
) -> List[Path]:
    """Generate audio for all slides in a lesson."""
    audio_files = []
    for i, slide in enumerate(lesson_json["slides"], 1):
        audio_path = generate_audio_for_slide(
            slide["speaker_notes"],
            output_dir / f"audio_{i:02d}.mp3"
        )
        audio_files.append(audio_path)
    return audio_files
Testing:

Generate audio for sample speaker notes
Verify audio quality and clarity
Verify duration matches slide content (not too fast/slow)


3.3 Video Assembly
Estimated Time: 4-5 hours
Files to Create:

src/vina_backend/services/video_renderer.py

Technology: MoviePy
Process:

Load slide PNGs
Load corresponding audio MP3s
For each slide:

Create video clip from PNG
Set duration = audio duration
Add audio track


Concatenate all clips
Export as MP4

Functions Required:
pythondef create_video_from_slides(
    slide_paths: List[Path],
    audio_paths: List[Path],
    output_path: Path
) -> Path:
    """
    Create MP4 video from slides and audio.
    
    Args:
        slide_paths: List of PNG paths
        audio_paths: List of MP3 paths (same length as slide_paths)
        output_path: Where to save MP4
    
    Returns:
        Path to generated MP4
    """
    from moviepy.editor import ImageClip, AudioFileClip, concatenate_videoclips
    
    clips = []
    for slide_path, audio_path in zip(slide_paths, audio_paths):
        # Load audio to get duration
        audio = AudioFileClip(str(audio_path))
        
        # Create video clip from image with audio duration
        video = ImageClip(str(slide_path), duration=audio.duration)
        video = video.set_audio(audio)
        
        clips.append(video)
    
    # Concatenate all clips
    final_video = concatenate_videoclips(clips, method="compose")
    
    # Export
    final_video.write_videofile(
        str(output_path),
        fps=24,
        codec='libx264',
        audio_codec='aac'
    )
    
    return output_path

def render_lesson_video(
    lesson_json: Dict,
    output_path: Path
) -> Path:
    """
    Full pipeline: lesson JSON → MP4 video.
    
    Steps:
    1. Render slides to PNGs
    2. Generate audio for each slide
    3. Assemble video
    4. Clean up temp files
    """
    # Create temp directory
    temp_dir = Path("cache/temp") / f"lesson_{uuid.uuid4()}"
    temp_dir.mkdir(parents=True, exist_ok=True)
    
    try:
        # Render slides
        slide_paths = render_lesson_slides(lesson_json, temp_dir)
        
        # Generate audio
        audio_paths = generate_lesson_audio(lesson_json, temp_dir)
        
        # Create video
        video_path = create_video_from_slides(slide_paths, audio_paths, output_path)
        
        return video_path
        
    finally:
        # Clean up temp files
        shutil.rmtree(temp_dir)
Testing:

Render full lesson video (5 slides)
Verify video plays correctly
Verify audio syncs with slides
Verify vertical format (1080×1920)
Verify file size is reasonable (<20 MB for 3-min video)


3.4 Cloudinary Integration
Estimated Time: 1-2 hours
Files to Create:

src/vina_backend/integrations/cloudinary/uploader.py

Functions Required:
pythondef upload_video(
    video_path: Path,
    public_id: str
) -> str:
    """
    Upload video to Cloudinary.
    
    Args:
        video_path: Path to MP4 file
        public_id: Unique ID for this video (e.g., "l01_clinical_researcher_pharma_d3")
    
    Returns:
        Streaming URL (https://res.cloudinary.com/...)
    """
    import cloudinary
    import cloudinary.uploader
    
    result = cloudinary.uploader.upload(
        str(video_path),
        resource_type="video",
        public_id=public_id,
        folder="vina/lessons"
    )
    
    return result["secure_url"]

def generate_public_id(
    lesson_id: str,
    profession: str,
    industry: str,
    difficulty: int,
    variant: Optional[str] = None
) -> str:
    """
    Generate unique ID for video.
    
    Examples:
        "l01_clinical_researcher_pharma_d3"
        "l05_hr_manager_tech_d1"
        "l08_marketing_manager_ecommerce_d3_more_examples"
    """
    safe_profession = profession.lower().replace(" ", "_")
    safe_industry = industry.lower().replace("/", "_").replace(" ", "_")
    
    parts = [lesson_id, safe_profession, safe_industry, f"d{difficulty}"]
    if variant:
        parts.append(variant)
    
    return "_".join(parts)
Testing:

Upload sample video
Verify URL is accessible
Verify video streams correctly
Test error handling (network issues, invalid files)


Phase 4: API & Frontend (Priority: HIGH)
4.1 API Endpoints
Estimated Time: 4-5 hours
Files to Create:

src/vina_backend/api/routers/profiles.py
src/vina_backend/api/routers/lessons.py
src/vina_backend/api/routers/quizzes.py
src/vina_backend/api/routers/sessions.py
src/vina_backend/api/main.py (FastAPI app)

Endpoints:
python# profiles.py
@router.post("/api/v1/profiles", response_model=UserProfileResponse)
async def create_or_get_profile(request: UserProfileRequest):
    """Generate or retrieve user profile."""
    profile = get_or_create_user_profile(
        request.profession,
        request.industry,
        request.experience_level
    )
    return UserProfileResponse(profile=profile, generated_from_cache=True)

# sessions.py
@router.post("/api/v1/sessions", response_model=SessionResponse)
async def create_session(request: SessionRequest):
    """Create a new learning session."""
    # request: {profile_id, course_id}
    session = create_session(request.profile_id, request.course_id)
    return SessionResponse(session=session)

@router.get("/api/v1/sessions/{session_id}")
async def get_session(session_id: str):
    """Get session state."""
    state = get_learner_state(session_id)
    return state

# lessons.py
@router.get("/api/v1/lessons/{lesson_id}")
async def get_lesson(
    lesson_id: str,
    session_id: str = Query(...)
):
    """
    Get lesson video URL.
    
    Flow:
    1. Get session state (knows profession, industry, current difficulty)
    2. Check cache: lesson_id + profession + industry + difficulty
    3. If cached: return URL immediately
    4. If not: generate, cache, return URL
    """
    state = get_learner_state(session_id)
    profile = get_user_profile(state.user_profile_id)
    
    # Check cache
    cache_key = f"{lesson_id}_{profile.profession}_{profile.industry}_d{state.current_difficulty}"
    cached_url = get_from_cache(cache_key)
    
    if cached_url:
        return {"video_url": cached_url, "from_cache": True}
    
    # Generate lesson
    lesson_json = generate_lesson(
        lesson_id=lesson_id,
        user_profile=profile,
        difficulty=state.current_difficulty,
        course_id=state.course_id
    )
    
    # Render video
    video_path = render_lesson_video(lesson_json, Path(f"cache/videos/{cache_key}.mp4"))
    
    # Upload to Cloudinary
    public_id = generate_public_id(lesson_id, profile.profession, profile.industry, state.current_difficulty)
    video_url = upload_video(video_path, public_id)
    
    # Cache URL
    cache_video_url(cache_key, video_url)
    
    return {"video_url": video_url, "from_cache": False}

@router.post("/api/v1/lessons/{lesson_id}/adapt")
async def adapt_lesson(
    lesson_id: str,
    request: AdaptRequest
):
    """
    Regenerate lesson with adaptation.
    
    request: {session_id, adaptation_type: "simplify_this" | "get_to_the_point" | "more_examples"}
    """
    state = get_learner_state(request.session_id)
    profile = get_user_profile(state.user_profile_id)
    
    # Calculate new difficulty
    if request.adaptation_type == "simplify_this":
        new_difficulty = 1
    elif request.adaptation_type == "get_to_the_point":
        new_difficulty = 5
    elif request.adaptation_type == "more_examples":
        # Serve pre-rendered "more examples" video
        cache_key = f"{lesson_id}_{profile.profession}_{profile.industry}_more_examples"
        video_url = get_from_cache(cache_key)
        return {"video_url": video_url, "from_cache": True}
    
    # Check cache for new difficulty
    cache_key = f"{lesson_id}_{profile.profession}_{profile.industry}_d{new_difficulty}"
    cached_url = get_from_cache(cache_key)
    
    if cached_url:
        # Update state
        update_difficulty(request.session_id, new_difficulty)
        return {"video_url": cached_url, "from_cache": True}
    
    # Generate at new difficulty
    lesson_json = generate_lesson(
        lesson_id=lesson_id,
        user_profile=profile,
        difficulty=new_difficulty,
        course_id=state.course_id,
        adaptation_context=request.adaptation_type
    )
    
    # Render, upload, cache
    video_path = render_lesson_video(lesson_json, Path(f"cache/videos/{cache_key}.mp4"))
    public_id = generate_public_id(lesson_id, profile.profession, profile.industry, new_difficulty)
    video_url = upload_video(video_path, public_id)
    cache_video_url(cache_key, video_url)
    
    # Update state
    update_difficulty(request.session_id, new_difficulty)
    record_adaptation(request.session_id, lesson_id, request.adaptation_type)
    
    return {"video_url": video_url, "from_cache": False}

# quizzes.py
@router.get("/api/v1/quizzes/{lesson_id}")
async def get_quiz(
    lesson_id: str,
    session_id: str = Query(...)
):
    """Get quiz for a lesson."""
    state = get_learner_state(session_id)
    profile = get_user_profile(state.user_profile_id)
    
    # Check if quiz is pre-generated
    cache_key = f"quiz_{lesson_id}_{profile.profession}_{profile.industry}"
    cached_quiz = get_quiz_from_cache(cache_key)
    
    if cached_quiz:
        return cached_quiz
    
    # Generate quiz
    quiz = generate_quiz(lesson_id, profile, state.course_id)
    cache_quiz(cache_key, quiz)
    
    return quiz

@router.post("/api/v1/quizzes/{lesson_id}/submit")
async def submit_quiz(
    lesson_id: str,
    request: QuizSubmission
):
    """
    Submit quiz answers and get score.
    
    request: {session_id, answers: ["A", "C", "B"]}
    """
    # Get quiz
    quiz = get_quiz(lesson_id, request.session_id)
    
    # Evaluate
    score, correctness = evaluate_quiz(quiz, request.answers)
    
    # Update learner state
    mark_lesson_complete(request.session_id, lesson_id, score)
    
    # Adjust difficulty for next lesson
    state = get_learner_state(request.session_id)
    if score == 3:
        new_difficulty = min(state.current_difficulty + 1, 5)
    elif score <= 1:
        new_difficulty = max(state.current_difficulty - 1, 1)
    else:
        new_difficulty = state.current_difficulty
    
    update_difficulty(request.session_id, new_difficulty)
    
    return {
        "score": score,
        "total": 3,
        "correctness": correctness,
        "next_difficulty": new_difficulty,
        "feedback_message": get_feedback_message(score)
    }
Testing:

Test profile creation via API
Test session creation
Test lesson retrieval (cache hit and cache miss)
Test adaptation flow
Test quiz retrieval and submission


4.2 Frontend (Next.js)
Estimated Time: 6-8 hours
Files to Create:

app/page.tsx (Landing page with profession/industry selection)
app/lesson/[lessonId]/page.tsx (Lesson player)
components/VideoPlayer.tsx (Vertical video player)
components/AdaptButton.tsx (Floating adapt button)
components/Quiz.tsx (MCQ quiz interface)
hooks/useSession.ts (Session state management)
lib/api.ts (API client functions)

Key Components:
VideoPlayer.tsx:
typescriptexport function VideoPlayer({ videoUrl, onComplete }: Props) {
  return (
    <div className="relative w-full max-w-md mx-auto aspect-[9/16] bg-black">
      <video
        src={videoUrl}
        controls
        className="w-full h-full"
        onEnded={onComplete}
      />
      
      <AdaptButton
        onAdapt={(type) => handleAdapt(type)}
        className="absolute bottom-20 right-4"
      />
    </div>
  );
}
AdaptButton.tsx:
typescriptexport function AdaptButton({ onAdapt }: Props) {
  const [isOpen, setIsOpen] = useState(false);
  
  return (
    <div className="relative">
      <button
        onClick={() => setIsOpen(!isOpen)}
        className="bg-blue-600 text-white px-6 py-3 rounded-full shadow-lg"
      >
        Adapt
      </button>
      
      {isOpen && (
        <div className="absolute bottom-full right-0 mb-2 bg-white rounded-lg shadow-xl p-2 min-w-[200px]">
          <button onClick={() => onAdapt('simplify_this')}>
            Simplify this
          </button>
          <button onClick={() => onAdapt('get_to_the_point')}>
            Get to the point
          </button>
          <button onClick={() => onAdapt('i_know_this_already')}>
            I know this already
          </button>
          <button onClick={() => onAdapt('more_examples')}>
            More examples
          </button>
        </div>
      )}
    </div>
  );
}
Quiz.tsx:
typescriptexport function Quiz({ quiz, onSubmit }: Props) {
  const [answers, setAnswers] = useState<string[]>([]);
  
  return (
    <div className="max-w-2xl mx-auto p-6">
      {quiz.questions.map((q, idx) => (
        <div key={idx} className="mb-6">
          <h3 className="font-bold mb-2">
            {idx + 1}. {q.question_text}
          </h3>
          
          <div className="space-y-2">
            {q.options.map((option) => (
              <label key={option} className="flex items-center">
                <input
                  type="radio"
                  name={`question_${idx}`}
                  value={option[0]}
                  onChange={(e) => {
                    const newAnswers = [...answers];
                    newAnswers[idx] = e.target.value;
                    setAnswers(newAnswers);
                  }}
                />
                <span className="ml-2">{option}</span>
              </label>
            ))}
          </div>
        </div>
      ))}
      
      <button
        onClick={() => onSubmit(answers)}
        disabled={answers.length !== quiz.questions.length}
        className="bg-blue-600 text-white px-6 py-3 rounded-lg"
      >
        Submit Quiz
      </button>
    </div>
  );
}
Session Management (useSession.ts):
typescriptexport function useSession() {
  const [sessionId, setSessionId] = useState<string | null>(null);
  const [state, setState] = useState<LearnerState | null>(null);
  
  useEffect(() => {
    // Load from localStorage
    const saved = localStorage.getItem('vina_session_id');
    if (saved) {
      setSessionId(saved);
      loadSession(saved);
    }
  }, []);
  
  const createSession = async (profileId: number, courseId: string) => {
    const response = await fetch('/api/v1/sessions', {
      method: 'POST',
      body: JSON.stringify({ profile_id: profileId, course_id: courseId })
    });
    const data = await response.json();
    
    setSessionId(data.session_id);
    localStorage.setItem('vina_session_id', data.session_id);
    setState(data);
  };
  
  const loadSession = async (id: string) => {
    const response = await fetch(`/api/v1/sessions/${id}`);
    const data = await response.json();
    setState(data);
  };
  
  return { sessionId, state, createSession, loadSession };
}
Testing:

Test profession/industry selection flow
Test video playback
Test adapt button (all 4 options)
Test quiz submission and feedback
Test session persistence (localStorage)
Test responsive design (mobile-first)


Phase 5: Pre-Generation & Deployment (Priority: CRITICAL)
5.1 Pre-Generation Scripts
Estimated Time: 3-4 hours
Files to Create:

scripts/pregenerate_profiles.py
scripts/pregenerate_lessons.py
scripts/pregenerate_quizzes.py
scripts/upload_to_cloudinary.py

pregenerate_profiles.py:
python"""
Pre-generate all 12 user profiles.
4 professions × 3 industries = 12 combos
"""
from vina_backend.services.profile_builder import get_or_create_user_profile
from vina_backend.domain.constants.enums import SUPPORTED_PROFESSIONS, INDUSTRIES_BY_PROFESSION

def pregenerate_all_profiles():
    """Generate and cache all 12 profiles."""
    for profession in SUPPORTED_PROFESSIONS:
        for industry in INDUSTRIES_BY_PROFESSION[profession]:
            print(f"Generating: {profession} in {industry}")
            
            profile = get_or_create_user_profile(
                profession=profession,
                industry=industry,
                experience_level="Intermediate",
                force_refresh=False  # Use cached if exists
            )
            
            print(f"  ✅ Saved to database")
    
    print(f"\n✅ Generated {len(SUPPORTED_PROFESSIONS) * 3} profiles")

if __name__ == "__main__":
    pregenerate_all_profiles()
pregenerate_lessons.py:
python"""
Pre-generate lesson videos for the hackathon demo.

Strategy:
- 5 lessons: L01, L02, L05, L08, L10
- 12 profession/industry combos
- 3 versions: default (d3), too_easy (d1), too_hard (d5)
- Total: 5 × 12 × 3 = 180 videos

For hackathon, can reduce to:
- 5 lessons × 12 combos × 1 version (default only) = 60 videos
- Generate adapted versions on-demand
"""
import asyncio
from pathlib import Path
from vina_backend.services.profile_builder import get_or_create_user_profile
from vina_backend.services.lesson_generator import generate_lesson
from vina_backend.services.video_renderer import render_lesson_video
from vina_backend.integrations.cloudinary.uploader import upload_video, generate_public_id
from vina_backend.domain.constants.enums import SUPPORTED_PROFESSIONS, INDUSTRIES_BY_PROFESSION

DEMO_LESSONS = ["l01_what_llms_are", "l02_tokens_context", "l05_hallucinations", 
                "l08_identifying_roi_tasks", "l10_designing_workflows"]

async def pregenerate_lesson(
    lesson_id: str,
    profession: str,
    industry: str,
    difficulty: int = 3
):
    """Generate one lesson video."""
    print(f"  Generating {lesson_id} for {profession} in {industry} at d{difficulty}")
    
    # Get profile
    profile = get_or_create_user_profile(profession, industry, "Intermediate")
    
    # Generate lesson content
    lesson_json = generate_lesson(
        lesson_id=lesson_id,
        user_profile=profile,
        difficulty=difficulty,
        course_id="c_llm_foundations"
    )
    
    # Render video
    cache_key = f"{lesson_id}_{profession.lower().replace(' ', '_')}_{industry.lower().replace('/', '_')}_d{difficulty}"
    video_path = Path(f"cache/videos/{cache_key}.mp4")
    render_lesson_video(lesson_json, video_path)
    
    # Upload to Cloudinary
    public_id = generate_public_id(lesson_id, profession, industry, difficulty)
    video_url = upload_video(video_path, public_id)
    
    # Cache URL in database
    cache_video_url(cache_key, video_url)
    
    print(f"    ✅ Uploaded: {video_url}")
    
    return video_url

async def pregenerate_all_lessons():
    """Generate all demo lessons."""
    tasks = []
    
    for lesson_id in DEMO_LESSONS:
        for profession in SUPPORTED_PROFESSIONS:
            for industry in INDUSTRIES_BY_PROFESSION[profession]:
                # Default version (difficulty 3)
                tasks.append(pregenerate_lesson(lesson_id, profession, industry, 3))
                
                # Optional: Also pre-generate adapted versions
                # tasks.append(pregenerate_lesson(lesson_id, profession, industry, 1))
                # tasks.append(pregenerate_lesson(lesson_id, profession, industry, 5))
    
    # Run in parallel (adjust concurrency based on API limits)
    results = await asyncio.gather(*tasks)
    
    print(f"\n✅ Generated {len(results)} lesson videos")

if __name__ == "__main__":
    asyncio.run(pregenerate_all_lessons())
pregenerate_quizzes.py:
python"""
Pre-generate all quizzes.
5 lessons × 12 combos = 60 quizzes
"""
from vina_backend.services.quiz_generator import generate_quiz
from vina_backend.services.profile_builder import get_or_create_user_profile

def pregenerate_all_quizzes():
    """Generate and cache all quizzes."""
    for lesson_id in DEMO_LESSONS:
        for profession in SUPPORTED_PROFESSIONS:
            for industry in INDUSTRIES_BY_PROFESSION[profession]:
                print(f"Generating quiz: {lesson_id} for {profession} in {industry}")
                
                profile = get_or_create_user_profile(profession, industry, "Intermediate")
                
                quiz = generate_quiz(
                    lesson_id=lesson_id,
                    user_profile=profile,
                    course_id="c_llm_foundations"
                )
                
                # Cache quiz in database
                cache_key = f"quiz_{lesson_id}_{profession}_{industry}"
                cache_quiz(cache_key, quiz)
                
                print(f"  ✅ Cached")
    
    print(f"\n✅ Generated 60 quizzes")

if __name__ == "__main__":
    pregenerate_all_quizzes()
Execution Strategy:
bash# Run overnight or during low-usage hours
uv run python scripts/pregenerate_profiles.py
uv run python scripts/pregenerate_quizzes.py
uv run python scripts/pregenerate_lessons.py  # This will take 4-6 hours

5.2 Deployment
Estimated Time: 2-3 hours
Backend (Railway):

Connect GitHub repo
Set environment variables (all API keys, DATABASE_URL)
Deploy from main branch
Upload pre-generated SQLite database with profiles/quizzes/video URLs

Frontend (Vercel):

Connect GitHub repo
Set environment variables (NEXT_PUBLIC_API_URL)
Deploy from main branch
Configure custom domain (optional)

Database:

For hackathon: SQLite file included in Railway deployment
For production: Migrate to PostgreSQL

Testing:

Verify API endpoints accessible
Verify video URLs resolve
Test full user flow (select profession → watch lesson → quiz → next lesson)


Pre-Generation Strategy
Demo Content Matrix
ComponentCountDetailsUser Profiles124 professions × 3 industriesLessons (default)605 lessons × 12 combos × difficulty 3Quizzes605 lessons × 12 combos"More Examples" Videos605 lessons × 12 combosTotal Videos12060 default + 60 more_examples
Why This Approach Works
For the demo:

✅ Instant response for all default paths (no generation latency)
✅ Shows true personalization (content visibly different per profession)
✅ Adapt button works (on-demand generation for adapted versions)

Storage:

120 videos × ~8 MB average = ~1 GB on Cloudinary (within free tier)

Generation Time:

120 videos × 2 minutes per video = 240 minutes = 4 hours (parallelizable to ~1-2 hours with batch processing)

Fallback Strategy
If time is tight, reduce to:

40 videos: 5 lessons × 4 professions (one industry per profession) × 2 versions (default + one_adaptation)
Generate on-demand during demo with loading states


Testing & Validation
Unit Tests

✅ Profile generation (all fields present, validation passes)
✅ Course config loading
✅ Lesson config retrieval
✅ Difficulty knob access
⚠️ Lesson generation (Generator → Reviewer → Rewriter pipeline)
⚠️ Quiz generation
⚠️ Video rendering

Integration Tests

⚠️ API endpoints (profile, session, lesson, quiz)
⚠️ Database operations (save, retrieve, update)
⚠️ Cloudinary upload/retrieval
⚠️ Full lesson generation pipeline (JSON → Video → Upload → Cache)

End-to-End Tests

⚠️ User selects profession → Profile generated → Session created
⚠️ User watches lesson → Video plays → Adapt button works
⚠️ User takes quiz → Score recorded → Difficulty adjusts
⚠️ User completes 5 lessons → Progress tracked

Demo Rehearsal

⚠️ Test on actual mobile device (vertical video, touch interactions)
⚠️ Verify fast response times (cached videos load instantly)
⚠️ Test adaptation flow (regeneration works, shows loading state)
⚠️ Verify quiz flow (submit, see results, move to next lesson)


Deployment Plan
Pre-Deployment Checklist

 All 120 videos pre-generated and uploaded to Cloudinary
 All 60 quizzes pre-generated and cached in database
 All 12 user profiles pre-generated
 Database seeded with video URLs and quiz data
 Environment variables configured in Railway and Vercel
 API endpoints tested (Postman/Insomnia)
 Frontend tested locally (npm run dev)

Deployment Steps

Backend:

Push to GitHub main branch
Railway auto-deploys
Upload SQLite database file to Railway (via SSH or file upload)
Test API: curl https://vina-api.railway.app/api/v1/health


Frontend:

Push to GitHub main branch
Vercel auto-deploys
Test homepage: https://vina.vercel.app


Smoke Test:

Select Clinical Researcher in Pharma
Watch Lesson 1 (should load instantly)
Click "Get to the point" (should regenerate or show loading)
Complete quiz (should show results and move to next lesson)




Success Criteria
Hackathon Judging Criteria
Functionality (25 points):

✅ Users can select profession/industry
✅ Personalized lessons generate correctly
✅ Adapt button works (all 4 options)
✅ Quizzes work and adapt difficulty
✅ Progress tracking works

Real-world relevance (20 points):

✅ Addresses genuine professional learning needs
✅ Examples are profession-specific and realistic
✅ Safety priorities tailored to industry regulations

Use of LLMs/Agents (25 points):

✅ Agentic pipeline (Generator → Reviewer → Rewriter)
✅ Multi-step reasoning (quality control, not just generation)
✅ Dynamic adaptation based on user feedback

Evaluation and observability (15 points):

⚠️ Opik integration tracks generation pipeline
⚠️ Metrics logged (latency, rewrite rate, cost per lesson)
⚠️ Dashboard shows agent interactions

Goal Alignment (15 points):

✅ Directly supports intellectual growth and upskilling
✅ Personalized learning experiences
✅ Respects user time with micro-lessons

Demo Success Metrics

Judges can complete full lesson flow (selection → lesson → quiz → next) in <5 minutes
Video loads instantly (cached) or within 20 seconds (generated)
Personalization is obvious (different examples for different professions)
No errors or crashes during demo


Risk Mitigation
RiskLikelihoodImpactMitigationVideo generation too slowMediumHighPre-generate all demo contentLLM API rate limitsMediumHighUse multiple providers, implement fallbacksMoviePy rendering errorsLowHighTest extensively, keep slides simpleCloudinary upload failuresLowMediumImplement retry logic, use local cacheDatabase corruptionLowHighBackup SQLite file before demoFrontend crash on mobileLowHighTest on actual devices, not just emulators

Timeline Summary
PhaseTasksEstimated TimeDependencies1.5: Missing ComponentsCourse Loader, UserProfile Model, Validation30 minNone2: Core PipelineLearner State, Prompts, Lesson Gen, Quiz Gen10-12 hoursPhase 1.53: Video PipelineSlide Rendering, TTS, Video Assembly, Cloudinary10-12 hoursPhase 24: API & FrontendFastAPI endpoints, Next.js UI10-12 hoursPhase 2, 35: Pre-Gen & DeployScripts, Deployment, Testing6-8 hoursPhase 2, 3, 4Total36-44 hours
Suggested Schedule (3-Day Sprint)
Day 1 (Friday Night / Saturday AM):

Phase 1.5 (30 min)
Phase 2: Learner State + Prompts (6 hours)

Day 2 (Saturday PM / Sunday AM):

Phase 2: Lesson Gen + Quiz Gen (4 hours)
Phase 3: Video Pipeline (10 hours)

Day 3 (Sunday PM):

Phase 4: API + Frontend (10 hours)
Phase 5: Pre-Gen + Deploy (6 hours)


Next Immediate Actions
Priority 1 (Do Now - 30 minutes):

Create src/vina_backend/services/course_loader.py
Verify src/vina_backend/integrations/db/models/user.py has safety fields
Create scripts/validate_setup.py and run it

Priority 2 (Do Next - 2 hours):

Create Learner State schema and database model
Create Learner State management service
Test session creation and state tracking

Priority 3 (Do Today - 4 hours):

Write lesson generation prompts (Generator, Reviewer, Rewriter)
Implement lesson generation service
Test lesson generation with sample inputs


Handoff Instructions
For Human Developer:
This PRD contains everything needed to complete Vina. Follow the phases in order. Each phase has detailed specifications, file paths, function signatures, and testing requirements. Start with Priority 1 actions.
For LLM Assistant:
This PRD is your complete specification. When asked to implement a component:

Read the relevant phase section
Follow the file structure exactly as specified
Implement all required functions with the exact signatures shown
Add appropriate error handling and logging
Write docstrings for all functions
Create basic tests for critical paths

Key Files Reference:

Global Config: src/vina_backend/domain/constants/course_config_global.json
Course Config: src/vina_backend/domain/constants/courses/llm_foundations.json
User Profile: src/vina_backend/domain/schemas/profile.py
Database Models: src/vina_backend/integrations/db/models/
Services: src/vina_backend/services/

Current Status: Phase 1 complete, Phase 1.5 pending (3 files to create), Phase 2-5 not started.

Document Version: 1.0
Last Updated: February 4, 2026
Maintained By: Vina Development Team
Next Review: After Phase 2 completion