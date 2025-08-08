#!/usr/bin/env python3
"""
LLM Interview Engine - A tool for running LLM-to-LLM research interviews
to evaluate problem/solution hypotheses for emotionally intelligent coaching products.
"""

import json
import os
import sys
import time
import random
import argparse
import asyncio
import aiohttp
from datetime import datetime
from pathlib import Path
from typing import Dict, List, Optional, Any
import openai
from dataclasses import dataclass, asdict
import logging
from dotenv import load_dotenv
from contextlib import nullcontext

# Configure logging
logging.basicConfig(level=logging.INFO)
logger = logging.getLogger(__name__)


@dataclass
class ProblemHypothesis:
    """
    Represents a problem hypothesis to be tested in LLM interviews.

    Attributes:
        label (str): A short identifier for the hypothesis
        description (str): Detailed description of the problem hypothesis
    """

    label: str
    description: str


@dataclass
class InterviewMode:
    """
    Represents an interview mode with its parameters and hypotheses.

    Attributes:
        mode (str): The interview mode identifier (e.g., "trauma_informed", "cognitive_behavioral")
        persona_count (int): Number of contrasting personas to generate (default: 3)
        problem_hypotheses (List[ProblemHypothesis]): List of hypotheses to test in this mode
    """

    mode: str
    persona_count: int = 3
    problem_hypotheses: List[ProblemHypothesis] = None

    def __post_init__(self):
        if self.problem_hypotheses is None:
            self.problem_hypotheses = []


@dataclass
class ProjectConfig:
    """
    Configuration for an LLM interview project.

    Attributes:
        project_name (str): Unique name for the project
        llm_model (str): OpenAI model to use for interviews (default: "gpt-4o-mini")
        product_sketch (str): Internal product description (not shared with personas)
        interview_modes (List[InterviewMode]): List of interview modes and their configurations
        output_format (str): Output format for interviews ("markdown" or "json")
        version (str): Version identifier for this configuration
    """

    project_name: str
    llm_model: str = "gpt-4o-mini"
    product_sketch: str = ""
    interview_modes: List[InterviewMode] = None
    output_format: str = "markdown"
    version: str = "v1"

    def __post_init__(self):
        if self.interview_modes is None:
            self.interview_modes = []


class NonDeterministicInterviewer:
    """
    Handles non-deterministic interview generation with unique personas and indirect hypothesis testing.

    This class ensures that:
    - Personas are unique across cycles
    - Hypotheses are hidden from personas during interviews
    - Questions are indirect and varied
    - Randomization is properly seeded
    """

    def __init__(self):
        """Initialize the non-deterministic interviewer."""
        self.question_templates = [
            "Tell me about a time when you felt {emotion} at work.",
            "What does a typical {time_period} look like for you?",
            "How do you usually handle {challenge}?",
            "What would make your {aspect} easier?",
            "When you're feeling {emotion}, what do you wish you had?",
            "What's the biggest {challenge} you face regularly?",
            "How do you know when you're {state}?",
            "What would success look like for you in terms of {goal}?",
            "What's one thing that would make a big difference in your {area}?",
            "How do you currently manage {situation}?",
        ]

        self.emotion_words = [
            "overwhelmed",
            "stressed",
            "anxious",
            "frustrated",
            "exhausted",
            "confident",
            "calm",
            "focused",
            "energized",
            "uncertain",
        ]

        self.challenge_words = [
            "pressure",
            "deadlines",
            "expectations",
            "responsibilities",
            "decisions",
            "conflicts",
            "changes",
            "uncertainty",
            "perfectionism",
        ]

    def _generate_seed(
        self, cycle_number: int, persona_variant: int, hypothesis_label: str
    ) -> int:
        """Generate a unique seed for randomization."""
        seed_string = f"{cycle_number}_{persona_variant}_{hypothesis_label}_{datetime.now().timestamp()}"
        return hash(seed_string) % (2**32)

    def generate_personas_for_cycle(self, cycle_number: int, count: int) -> List[Dict]:
        """Generate unique personas for a specific cycle."""
        personas = []

        for i in range(count):
            seed = self._generate_seed(cycle_number, i, f"persona_{i}")
            random.seed(seed)

            persona = {
                "age_group": random.choice(
                    [
                        "early 20s",
                        "late 20s",
                        "early 30s",
                        "late 30s",
                        "early 40s",
                        "late 40s",
                        "early 50s",
                    ]
                ),
                "life_stage": random.choice(
                    [
                        "student",
                        "early career",
                        "mid-career",
                        "career transition",
                        "established professional",
                        "returning to work",
                    ]
                ),
                "emotional_baseline": random.choice(
                    [
                        "anxious",
                        "depressed",
                        "overwhelmed",
                        "numb",
                        "frustrated",
                        "hopeful",
                        "determined",
                        "exhausted",
                    ]
                ),
                "coping_style": random.choice(
                    [
                        "avoidant",
                        "confrontational",
                        "support-seeking",
                        "self-reliant",
                        "distraction-based",
                        "reflective",
                    ]
                ),
                "readiness_level": random.choice(
                    [
                        "resistant",
                        "ambivalent",
                        "curious",
                        "ready",
                        "desperate",
                        "cautious",
                    ]
                ),
                "background_factor": random.choice(
                    [
                        "trauma history",
                        "perfectionism",
                        "people-pleasing",
                        "imposter syndrome",
                        "burnout",
                        "caregiver stress",
                        "work-life imbalance",
                    ]
                ),
                "unique_challenge": random.choice(
                    [
                        "financial stress",
                        "relationship issues",
                        "health concerns",
                        "career uncertainty",
                        "identity crisis",
                        "social isolation",
                        "time management",
                    ]
                ),
            }
            personas.append(persona)

        return personas

    def create_indirect_questions(self, hypothesis: ProblemHypothesis) -> List[str]:
        """Create indirect questions to test a hypothesis without revealing it."""
        # Extract key concepts from hypothesis
        hypothesis_text = hypothesis.description.lower()

        # Identify indirect themes to explore
        themes = []
        if any(word in hypothesis_text for word in ["boundary", "limit", "no"]):
            themes.extend(["work pressure", "expectations", "time management"])
        if any(
            word in hypothesis_text for word in ["imposter", "confidence", "competence"]
        ):
            themes.extend(["self-doubt", "achievements", "recognition"])
        if any(word in hypothesis_text for word in ["overwhelm", "stress", "anxiety"]):
            themes.extend(["daily challenges", "coping", "support"])
        if any(
            word in hypothesis_text for word in ["productivity", "focus", "efficiency"]
        ):
            themes.extend(["workflow", "distractions", "energy"])

        # Generate questions based on themes
        questions = []
        for theme in themes:
            template = random.choice(self.question_templates)
            emotion = random.choice(self.emotion_words)
            challenge = random.choice(self.challenge_words)

            question = template.format(
                emotion=emotion,
                time_period="day",
                challenge=challenge,
                aspect=theme,
                state="overwhelmed",
                goal=theme,
                area=theme,
                situation=theme,
            )
            questions.append(question)

        return questions[:7]  # Return 7 questions

    def create_interview_prompt(
        self, hypothesis: ProblemHypothesis, persona_variant: int, cycle_number: int
    ) -> str:
        """Create an interview prompt that hides the hypothesis from the persona."""
        seed = self._generate_seed(cycle_number, persona_variant, hypothesis.label)
        random.seed(seed)

        # Generate unique persona
        persona = self.generate_personas_for_cycle(cycle_number, 1)[0]

        # Create indirect questions
        questions = self.create_indirect_questions(hypothesis)

        prompt = f"""You are conducting a research interview. The persona you're interviewing has these characteristics:
- Age Group: {persona['age_group']}
- Life Stage: {persona['life_stage']}
- Emotional Baseline: {persona['emotional_baseline']}
- Coping Style: {persona['coping_style']}
- Readiness Level: {persona['readiness_level']}
- Background Factor: {persona['background_factor']}
- Unique Challenge: {persona['unique_challenge']}

Conduct a natural conversation using these questions (but don't ask them all at once - make it conversational):

{chr(10).join(f"{i+1}. {q}" for i, q in enumerate(questions))}

Focus on understanding their lived experience, challenges, and what would help them. Do NOT mention any specific solutions or hypotheses."""

        return prompt


class InsightAnalyzer:
    """
    Analyzes interview insights to extract evolution signals and recommendations.
    """

    def __init__(self):
        """Initialize the insight analyzer."""
        pass

    def extract_evolution_signals(self, insights: List[Dict]) -> Dict:
        """Extract evolution signals from interview insights."""
        signals = {
            "alignment_rate": 0.0,
            "misaligned_hypotheses": [],
            "aligned_hypotheses": [],
            "common_pain_points": [],
            "success_patterns": [],
            "evolution_priorities": [],
        }

        total_insights = len(insights)
        aligned_count = 0

        for insight in insights:
            insight_text = insight.get("insights", "").lower()

            # Check alignment
            if "aligned? yes" in insight_text:
                aligned_count += 1
                signals["aligned_hypotheses"].append(
                    insight.get("hypothesis", "Unknown")
                )
            elif "aligned? no" in insight_text:
                signals["misaligned_hypotheses"].append(
                    insight.get("hypothesis", "Unknown")
                )

            # Extract pain points
            if "pain points:" in insight_text:
                try:
                    pain_section = insight_text.split("pain points:")[1].split(
                        "desired outcomes:"
                    )[0]
                    pain_points = [
                        p.strip() for p in pain_section.split("-") if p.strip()
                    ]
                    signals["common_pain_points"].extend(pain_points)
                except IndexError:
                    pass

        # Calculate alignment rate
        if total_insights > 0:
            signals["alignment_rate"] = aligned_count / total_insights

        # Generate evolution priorities
        if signals["misaligned_hypotheses"]:
            signals["evolution_priorities"].append("address misaligned hypotheses")
        if signals["common_pain_points"]:
            signals["evolution_priorities"].append("focus on common pain points")

        return signals

    def identify_product_gaps(self, insights: List[Dict]) -> List[str]:
        """Identify product gaps from insights."""
        gaps = []

        for insight in insights:
            insight_text = insight.get("insights", "").lower()

            if "aligned? no" in insight_text:
                if "specific tools" in insight_text:
                    gaps.append("Need for specific tools")
                if "concrete solutions" in insight_text:
                    gaps.append("Need for concrete solutions")
                if "better support" in insight_text:
                    gaps.append("Need for better support")

        return list(set(gaps))

    def quantify_feedback_strength(self, insights: List[Dict]) -> float:
        """Quantify the strength of feedback from insights."""
        if not insights:
            return 0.0

        strength_indicators = 0
        total_indicators = 0

        for insight in insights:
            insight_text = insight.get("insights", "").lower()

            # Strong negative feedback
            if "aligned? no" in insight_text and any(
                word in insight_text for word in ["major", "critical", "urgent"]
            ):
                strength_indicators += 2
            elif "aligned? no" in insight_text:
                strength_indicators += 1

            # Strong positive feedback
            if "aligned? yes" in insight_text and any(
                word in insight_text for word in ["excellent", "perfect", "ideal"]
            ):
                strength_indicators += 2
            elif "aligned? yes" in insight_text:
                strength_indicators += 1

            total_indicators += 1

        return strength_indicators / total_indicators if total_indicators > 0 else 0.0

    def generate_evolution_recommendations(self, signals: Dict) -> List[str]:
        """Generate evolution recommendations based on signals."""
        recommendations = []

        if signals["misaligned_hypotheses"]:
            recommendations.append(
                f"Refocus on hypotheses: {', '.join(signals['misaligned_hypotheses'])}"
            )

        if signals["common_pain_points"]:
            recommendations.append(
                f"Address common pain points: {', '.join(signals['common_pain_points'][:3])}"
            )

        if signals["alignment_rate"] < 0.5:
            recommendations.append("Significantly revise product approach")

        if signals["success_patterns"]:
            recommendations.append(
                f"Build on successful patterns: {', '.join(signals['success_patterns'])}"
            )

        return recommendations

    def track_improvement_metrics(self, cycle_results: List[Dict]) -> Dict:
        """Track improvement metrics across cycles."""
        if len(cycle_results) < 2:
            return {"alignment_improvement": 0.0}

        first_cycle = cycle_results[0].get("alignment_rate", 0.0)
        last_cycle = cycle_results[-1].get("alignment_rate", 0.0)

        return {
            "alignment_improvement": last_cycle - first_cycle,
            "cycles_completed": len(cycle_results),
            "final_alignment": last_cycle,
        }


class ProductEvolutionEngine:
    """
    Handles automatic product evolution based on interview insights.
    """

    def __init__(self):
        """Initialize the product evolution engine."""
        self.evolution_history = []

    def analyze_insights_for_evolution(self, insights: List[Dict]) -> Dict:
        """Analyze insights to identify evolution opportunities."""
        analyzer = InsightAnalyzer()
        return analyzer.extract_evolution_signals(insights)

    def generate_new_product_sketch(
        self, current_sketch: str, evolution_signals: Dict
    ) -> str:
        """Generate a new product sketch based on evolution signals."""
        # Extract key information for evolution
        misaligned = evolution_signals.get("misaligned_hypotheses", [])
        pain_points = evolution_signals.get("common_pain_points", [])
        priorities = evolution_signals.get("evolution_priorities", [])

        # Create evolution prompt
        evolution_prompt = f"""Current product sketch: {current_sketch}

Based on user feedback, the following issues were identified:
- Misaligned hypotheses: {', '.join(misaligned)}
- Common pain points: {', '.join(pain_points[:5])}
- Evolution priorities: {', '.join(priorities)}

Please evolve this product sketch to better address these issues. Focus on:
1. Addressing the specific pain points identified
2. Creating concrete, actionable solutions
3. Maintaining the core value proposition
4. Making the approach more specific and targeted

New product sketch:"""

        # For now, return a simple evolution (in real implementation, this would call LLM)
        new_sketch = (
            current_sketch + f"\n\nEvolved to address: {', '.join(pain_points[:3])}"
        )
        return new_sketch

    def create_new_hypotheses(self, evolution_signals: Dict) -> List[ProblemHypothesis]:
        """Create new hypotheses based on feedback."""
        misaligned = evolution_signals.get("misaligned_hypotheses", [])
        pain_points = evolution_signals.get("common_pain_points", [])
        successful_patterns = evolution_signals.get("success_patterns", [])

        new_hypotheses = []

        # Create hypotheses based on pain points
        for pain_point in pain_points[:3]:  # Top 3 pain points
            hypothesis = ProblemHypothesis(
                label=f"Address {pain_point.replace(' ', '_')}",
                description=f"Users struggle with {pain_point}. We're testing whether specific tools and approaches can help them overcome this challenge effectively.",
            )
            new_hypotheses.append(hypothesis)

        # Create hypotheses based on successful patterns
        for pattern in successful_patterns[:2]:  # Top 2 patterns
            hypothesis = ProblemHypothesis(
                label=f"Leverage {pattern.replace(' ', '_')}",
                description=f"Users responded positively to {pattern}. We're exploring how to expand and improve this approach.",
            )
            new_hypotheses.append(hypothesis)

        return new_hypotheses

    def validate_evolution_quality(
        self, original_config: ProjectConfig, evolved_config: ProjectConfig
    ) -> float:
        """Validate the quality of evolution between configurations."""
        # Simple quality assessment based on sketch length and specificity
        original_length = len(original_config.product_sketch)
        evolved_length = len(evolved_config.product_sketch)

        # Quality factors
        length_improvement = min(evolved_length / original_length, 2.0)  # Cap at 2x
        specificity_score = 0.5  # Placeholder for more sophisticated analysis

        quality_score = (length_improvement + specificity_score) / 2
        return min(quality_score, 1.0)

    def record_evolution(
        self,
        original_config: ProjectConfig,
        evolved_config: ProjectConfig,
        metadata: Dict,
    ):
        """Record an evolution in the history."""
        evolution_record = {
            "timestamp": datetime.now().isoformat(),
            "from_version": original_config.version,
            "to_version": evolved_config.version,
            "reason": metadata.get("reason", "Unknown"),
            "quality_score": self.validate_evolution_quality(
                original_config, evolved_config
            ),
        }
        self.evolution_history.append(evolution_record)

    def generate_evolution_report(
        self,
        original_config: ProjectConfig,
        evolved_config: ProjectConfig,
        metadata: Dict,
    ) -> str:
        """Generate a report documenting the evolution."""
        quality_score = self.validate_evolution_quality(original_config, evolved_config)

        report = f"""# Evolution Report

## Evolution Summary
- **From Version:** {original_config.version}
- **To Version:** {evolved_config.version}
- **Quality Score:** {quality_score:.2f}
- **Reason:** {metadata.get('reason', 'Unknown')}

## Changes Made
- **Original Sketch:** {original_config.product_sketch[:200]}...
- **Evolved Sketch:** {evolved_config.product_sketch[:200]}...

## Quality Assessment
- **Improvement Score:** {quality_score:.1%}
- **Recommendation:** {'Continue evolution' if quality_score > 0.7 else 'Consider further refinement'}

## Next Steps
- Monitor alignment in next cycle
- Validate new hypotheses
- Track user feedback improvements
"""
        return report


class IterativeResearchEngine:
    """
    Main engine for running iterative research cycles with automatic product evolution.
    Each cycle: Generate personas → Perform interviews → Aggregate insights → Evolve config → Repeat
    """

    def __init__(
        self,
        api_key: Optional[str] = None,
        config_dir: Optional[str] = None,
        cycles: int = 3,
        evolution_enabled: bool = True,
    ):
        """
        Initialize the iterative research engine.

        Args:
            api_key: OpenAI API key
            config_dir: Directory containing versioned configs
            cycles: Number of iteration cycles to run
            evolution_enabled: Whether to enable automatic product evolution
        """
        self.base_engine = LLMInterviewEngine(api_key=api_key, config_dir=config_dir)
        self.cycles = cycles
        self.evolution_enabled = evolution_enabled
        self.current_cycle = 0
        self.evolution_history = []
        self.product_evolution_engine = ProductEvolutionEngine()
        self.non_deterministic_interviewer = NonDeterministicInterviewer()

        # Load initial config
        self.current_config = self._load_current_config()

    def _load_current_config(self) -> ProjectConfig:
        """Load the current configuration from the config directory."""
        if hasattr(self.base_engine, "config_path") and self.base_engine.config_path:
            config_path = self.base_engine.config_path / "ygt_config.json"
            return self.base_engine._load_json_config(str(config_path))
        else:
            # Fallback to a default config
            return ProjectConfig(
                project_name="IterativeResearch",
                product_sketch="Default product sketch",
                interview_modes=[],
            )

    def _save_evolved_config(self, config: ProjectConfig):
        """Save the evolved configuration back to the config directory."""
        if hasattr(self.base_engine, "config_path") and self.base_engine.config_path:
            config_path = self.base_engine.config_path / "ygt_config.json"

            # Convert config to dict and save
            config_dict = self.base_engine._config_to_dict(config)
            with open(config_path, "w") as f:
                json.dump(config_dict, f, indent=2)

            print(f"💾 Saved evolved config to {config_path}")

    def _create_cycle_metadata(self, cycle_number: int) -> Dict:
        """Create metadata for a cycle."""
        return {
            "cycle_number": cycle_number,
            "timestamp": datetime.now().isoformat(),
            "config_version": (
                getattr(self.base_engine, "config_path", Path()).name
                if hasattr(self.base_engine, "config_path")
                else "unknown"
            ),
            "total_cycles": self.cycles,
            "evolution_enabled": self.evolution_enabled,
        }

    def _run_single_cycle(self) -> Dict:
        """Run a single iteration cycle: Generate personas → Perform interviews → Aggregate insights → Evolve config."""
        self.current_cycle += 1
        cycle_start = datetime.now()

        print(f"\n🔄 Starting Cycle {self.current_cycle}/{self.cycles}")
        print(
            f"📋 Current config: {self.current_config.project_name} v{self.current_config.version}"
        )

        try:
            # Step 1: Generate unique personas for this cycle
            print("👥 Generating unique personas for this cycle...")
            total_personas = sum(
                mode.persona_count for mode in self.current_config.interview_modes
            )
            personas = self.non_deterministic_interviewer.generate_personas_for_cycle(
                self.current_cycle, total_personas
            )
            print(f"✅ Generated {len(personas)} unique personas")

            # Step 2: Perform interviews using the current config
            print("🎤 Performing interviews...")
            results = self.base_engine._run_interviews(self.current_config)

            # Step 3: Aggregate insights
            insights = results.get("all_insights", [])
            alignment_rate = 0.0
            if insights:
                aligned_count = sum(
                    1
                    for insight in insights
                    if "Aligned? Yes" in insight.get("insights", "")
                )
                alignment_rate = aligned_count / len(insights)

            print(
                f"📊 Aggregated {len(insights)} insights, alignment rate: {alignment_rate:.1%}"
            )

            # Step 4: Evolve config if enabled and not the last cycle
            evolved_config = None
            evolution_signals = None

            if self.evolution_enabled and self.current_cycle < self.cycles:
                print("🔄 Evolving configuration...")
                evolution_signals = (
                    self.product_evolution_engine.analyze_insights_for_evolution(
                        insights
                    )
                )

                # Generate new product sketch
                new_sketch = self.product_evolution_engine.generate_new_product_sketch(
                    self.current_config.product_sketch, evolution_signals
                )

                # Create new hypotheses
                new_hypotheses = self.product_evolution_engine.create_new_hypotheses(
                    evolution_signals
                )

                # Create evolved config
                evolved_config = ProjectConfig(
                    project_name=self.current_config.project_name,
                    llm_model=self.current_config.llm_model,
                    product_sketch=new_sketch,
                    interview_modes=self.current_config.interview_modes,  # Keep same modes for now
                    output_format=self.current_config.output_format,
                    version=f"v{self.current_cycle + 1}",
                )

                # Update hypotheses in the first mode (simplified approach)
                if evolved_config.interview_modes and new_hypotheses:
                    evolved_config.interview_modes[0].problem_hypotheses = (
                        new_hypotheses
                    )

                # Record evolution
                self.product_evolution_engine.record_evolution(
                    self.current_config,
                    evolved_config,
                    {
                        "reason": f"Cycle {self.current_cycle} insights",
                        "signals": evolution_signals,
                    },
                )

                # Save evolved config
                self._save_evolved_config(evolved_config)

                # Update current config for next cycle
                self.current_config = evolved_config

                print(f"✅ Evolved config to v{evolved_config.version}")
                print(
                    f"📈 Evolution signals: {len(evolution_signals.get('misaligned_hypotheses', []))} misaligned hypotheses"
                )

            cycle_duration = (datetime.now() - cycle_start).total_seconds()

            return {
                "cycle_number": self.current_cycle,
                "success": True,
                "insights_count": len(insights),
                "alignment_rate": alignment_rate,
                "duration": cycle_duration,
                "all_insights": insights,
                "personas_generated": len(personas),
                "config_evolved": evolved_config is not None,
                "evolution_signals": evolution_signals,
                "config_version": self.current_config.version,
            }

        except Exception as e:
            cycle_duration = (datetime.now() - cycle_start).total_seconds()
            print(f"❌ Cycle {self.current_cycle} failed: {str(e)}")
            return {
                "cycle_number": self.current_cycle,
                "success": False,
                "error": str(e),
                "duration": cycle_duration,
                "insights_count": 0,
                "alignment_rate": 0.0,
                "personas_generated": 0,
                "config_evolved": False,
            }

    def run_iterative_research(self) -> List[Dict]:
        """Run the complete iterative research process with N cycles."""
        print(f"🚀 Starting iterative research with {self.cycles} cycles")
        print(
            f"📁 Config directory: {getattr(self.base_engine, 'config_path', 'unknown')}"
        )
        print(f"🔄 Evolution enabled: {self.evolution_enabled}")

        results = []

        for cycle in range(self.cycles):
            # Run the complete iteration cycle
            cycle_result = self._run_single_cycle()
            results.append(cycle_result)

            # Print cycle summary
            if cycle_result["success"]:
                print(f"✅ Cycle {cycle_result['cycle_number']} completed successfully")
                print(f"   📊 Alignment: {cycle_result['alignment_rate']:.1%}")
                print(f"   👥 Personas: {cycle_result['personas_generated']}")
                print(f"   ⏱️  Duration: {cycle_result['duration']:.1f}s")
                if cycle_result["config_evolved"]:
                    print(f"   🔄 Config evolved to: {cycle_result['config_version']}")
            else:
                print(
                    f"❌ Cycle {cycle_result['cycle_number']} failed: {cycle_result.get('error', 'Unknown error')}"
                )

            # Add a separator between cycles
            if cycle < self.cycles - 1:
                print("\n" + "=" * 50 + "\n")

        # Print final summary
        self._print_final_summary(results)

        return results

    def _print_final_summary(self, results: List[Dict]):
        """Print a summary of all cycles."""
        successful_cycles = [r for r in results if r["success"]]
        failed_cycles = [r for r in results if not r["success"]]

        print("\n" + "=" * 60)
        print("🎯 ITERATIVE RESEARCH SUMMARY")
        print("=" * 60)

        print(f"📊 Total Cycles: {len(results)}")
        print(f"✅ Successful: {len(successful_cycles)}")
        print(f"❌ Failed: {len(failed_cycles)}")

        if successful_cycles:
            avg_alignment = sum(r["alignment_rate"] for r in successful_cycles) / len(
                successful_cycles
            )
            total_insights = sum(r["insights_count"] for r in successful_cycles)
            total_personas = sum(r["personas_generated"] for r in successful_cycles)
            total_duration = sum(r["duration"] for r in successful_cycles)
            evolved_cycles = sum(1 for r in successful_cycles if r["config_evolved"])

            print(f"📈 Average Alignment: {avg_alignment:.1%}")
            print(f"💡 Total Insights: {total_insights}")
            print(f"👥 Total Personas: {total_personas}")
            print(f"⏱️  Total Duration: {total_duration:.1f}s")
            print(f"🔄 Config Evolutions: {evolved_cycles}")

            # Show alignment progression
            if len(successful_cycles) > 1:
                first_alignment = successful_cycles[0]["alignment_rate"]
                last_alignment = successful_cycles[-1]["alignment_rate"]
                improvement = last_alignment - first_alignment
                print(f"📈 Alignment Improvement: {improvement:+.1%}")

        if self.evolution_history:
            print(
                f"\n📚 Evolution History: {len(self.evolution_history)} recorded evolutions"
            )
            for i, evolution in enumerate(
                self.evolution_history[-3:], 1
            ):  # Show last 3
                print(
                    f"   {i}. {evolution['from_version']} → {evolution['to_version']} (Quality: {evolution['quality_score']:.2f})"
                )

    def _generate_cycle_summary(self, cycle_result: Dict) -> str:
        """Generate a summary for a cycle result."""
        return f"""Cycle {cycle_result['cycle_number']} Summary:
- Status: {'✅ Success' if cycle_result['success'] else '❌ Failed'}
- Insights: {cycle_result['insights_count']}
- Alignment: {cycle_result['alignment_rate']:.1%}
- Duration: {cycle_result['duration']:.1f}s
- Personas: {cycle_result['personas_generated']}
- Config Evolved: {'Yes' if cycle_result.get('config_evolved', False) else 'No'}"""


class AsyncPersonaGenerator:
    """
    Asynchronous persona generator for concurrent persona creation.
    """

    def __init__(self, api_key: Optional[str] = None):
        """Initialize the async persona generator."""
        # Load API key from .env if not provided
        if api_key is None:
            from dotenv import load_dotenv

            load_dotenv()
            api_key = os.getenv("OPENAI_API_KEY")

        self.api_key = api_key
        self.question_templates = [
            "Tell me about a time when you felt {emotion} at work.",
            "What does a typical {time_period} look like for you?",
            "How do you usually handle {challenge}?",
            "What would make your {aspect} easier?",
            "When you're feeling {emotion}, what do you wish you had?",
            "What's the biggest {challenge} you face regularly?",
            "How do you know when you're {state}?",
            "What would success look like for you in terms of {goal}?",
            "What's one thing that would make a big difference in your {area}?",
            "How do you currently manage {situation}?",
        ]

        self.emotion_words = [
            "overwhelmed",
            "stressed",
            "anxious",
            "frustrated",
            "exhausted",
            "confident",
            "calm",
            "focused",
            "energized",
            "uncertain",
        ]

        self.challenge_words = [
            "pressure",
            "deadlines",
            "expectations",
            "responsibilities",
            "decisions",
            "conflicts",
            "changes",
            "uncertainty",
            "perfectionism",
        ]

    async def _generate_seed_async(
        self, cycle_number: int, persona_variant: int, hypothesis_label: str
    ) -> int:
        """Generate a unique seed for randomization asynchronously."""
        seed_string = f"{cycle_number}_{persona_variant}_{hypothesis_label}_{datetime.now().timestamp()}"
        return hash(seed_string) % (2**32)

    async def generate_personas_async(
        self, count: int, cycle_number: int
    ) -> List[Dict]:
        """Generate unique personas for a specific cycle asynchronously."""
        personas = []

        # Create tasks for concurrent persona generation
        tasks = []
        for i in range(count):
            task = self._generate_single_persona_async(cycle_number, i)
            tasks.append(task)

        # Execute all persona generation concurrently
        personas = await asyncio.gather(*tasks)

        return personas

    async def _generate_single_persona_async(
        self, cycle_number: int, persona_variant: int
    ) -> Dict:
        """Generate a single persona asynchronously using LLM."""
        seed = await self._generate_seed_async(
            cycle_number, persona_variant, f"persona_{persona_variant}"
        )
        random.seed(seed)

        # Generate random elements for variety
        random_elements = {
            "age_group": random.choice(
                [
                    "early 20s",
                    "late 20s",
                    "early 30s",
                    "late 30s",
                    "early 40s",
                    "late 40s",
                    "early 50s",
                ]
            ),
            "life_stage": random.choice(
                [
                    "student",
                    "early career",
                    "mid-career",
                    "career transition",
                    "established professional",
                    "returning to work",
                ]
            ),
            "emotional_baseline": random.choice(
                [
                    "anxious",
                    "depressed",
                    "overwhelmed",
                    "numb",
                    "frustrated",
                    "hopeful",
                    "determined",
                    "exhausted",
                ]
            ),
            "coping_style": random.choice(
                [
                    "avoidant",
                    "confrontational",
                    "support-seeking",
                    "self-reliant",
                    "distraction-based",
                    "reflective",
                ]
            ),
            "readiness_level": random.choice(
                ["resistant", "ambivalent", "curious", "ready", "desperate", "cautious"]
            ),
            "background_factor": random.choice(
                [
                    "trauma history",
                    "perfectionism",
                    "people-pleasing",
                    "imposter syndrome",
                    "burnout",
                    "caregiver stress",
                    "work-life imbalance",
                ]
            ),
            "unique_challenge": random.choice(
                [
                    "financial stress",
                    "relationship issues",
                    "health concerns",
                    "career uncertainty",
                    "identity crisis",
                    "social isolation",
                    "time management",
                ]
            ),
        }

        # Create prompt for LLM persona generation
        prompt = f"""Create a realistic persona for user research interviews.

Context: This is for cycle {cycle_number}, persona variant {persona_variant} of a wellness app research study.

Please create a detailed persona with the following structure:
- name: A realistic name and age
- emotional_baseline: {random_elements['emotional_baseline']}
- background: A detailed background story incorporating {random_elements['life_stage']}, {random_elements['background_factor']}, and {random_elements['unique_challenge']}
- coping_style: {random_elements['coping_style']}
- readiness_level: {random_elements['readiness_level']}

Make the persona realistic and detailed. Focus on their emotional state, challenges, and how they might interact with wellness tools.

Respond in JSON format:
{{
    "name": "Full Name, Age",
    "emotional_baseline": "emotional state",
    "background": "detailed background story",
    "coping_style": "how they cope",
    "readiness_level": "their readiness for change"
}}"""

        # If we have an API key, call the LLM to generate a realistic persona
        if self.api_key:
            try:
                # Create a session for API calls
                import aiohttp

                async with aiohttp.ClientSession() as session:
                    headers = {
                        "Authorization": f"Bearer {self.api_key}",
                        "Content-Type": "application/json",
                    }

                    data = {
                        "model": "gpt-4o-mini",
                        "messages": [{"role": "user", "content": prompt}],
                        "max_tokens": 500,
                        "temperature": 0.7,
                    }

                    async with session.post(
                        "https://api.openai.com/v1/chat/completions",
                        headers=headers,
                        json=data,
                    ) as response:
                        if response.status == 200:
                            result = await response.json()
                            llm_response = result["choices"][0]["message"]["content"]

                            # Try to parse JSON response
                            try:
                                import json

                                persona_data = json.loads(llm_response)
                                return persona_data
                            except json.JSONDecodeError:
                                # Fall back to random persona if LLM response isn't valid JSON
                                pass
            except Exception as e:
                print(f"Warning: Could not call LLM for persona generation: {e}")
                # Fall back to random persona

        # Return random persona as fallback
        return {
            "name": f"Persona {persona_variant}",
            "emotional_baseline": random_elements["emotional_baseline"],
            "background": f"A {random_elements['age_group']} {random_elements['life_stage']} dealing with {random_elements['background_factor']} and {random_elements['unique_challenge']}",
            "coping_style": random_elements["coping_style"],
            "readiness_level": random_elements["readiness_level"],
        }


class AsyncInterviewProcessor:
    """
    Asynchronous interview processor for concurrent interview execution.
    """

    def __init__(
        self,
        api_key: str,
        max_concurrent: int = None,
        rate_limit_per_minute: int = None,
    ):
        """
        Initialize the async interview processor.

        Args:
            api_key: OpenAI API key
            max_concurrent: Maximum concurrent interviews (None = unlimited)
            rate_limit_per_minute: Rate limit for API calls per minute (None = unlimited)
        """
        self.api_key = api_key
        self.max_concurrent = max_concurrent
        self.rate_limit_per_minute = rate_limit_per_minute

        # Only create semaphores if limits are specified
        self.semaphore = asyncio.Semaphore(max_concurrent) if max_concurrent else None
        self.rate_limiter = (
            asyncio.Semaphore(rate_limit_per_minute) if rate_limit_per_minute else None
        )
        self.session = None

    async def __aenter__(self):
        """Async context manager entry."""
        self.session = aiohttp.ClientSession()
        return self

    async def __aexit__(self, exc_type, exc_val, exc_tb):
        """Async context manager exit."""
        if self.session:
            await self.session.close()

    async def process_interview_async(
        self,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona: Dict,
        persona_variant: int,
        run_timestamp: str,
    ) -> Dict:
        """Process a single interview asynchronously."""
        # Apply concurrency limits only if specified
        semaphore_context = self.semaphore if self.semaphore else nullcontext()
        rate_limit_context = self.rate_limiter if self.rate_limiter else nullcontext()

        async with semaphore_context:
            async with rate_limit_context:
                try:
                    # Generate interview prompt
                    prompt = self._generate_interview_prompt_async(
                        config,
                        mode,
                        hypothesis,
                        persona,
                        persona_variant,
                        run_timestamp,
                    )

                    # Call OpenAI API asynchronously
                    response = await self._call_openai_async(prompt, config.llm_model)

                    # Parse response
                    if config.output_format == "markdown":
                        result = self._parse_markdown_response(response)
                    else:
                        result = self._parse_json_response(response)

                    return {
                        "success": True,
                        "mode": mode.mode,
                        "hypothesis": hypothesis.label,
                        "persona_variant": persona_variant,
                        "insights": result.get("insights", ""),
                        "persona": result.get("persona", ""),
                        "interview_transcript": result.get("interview_transcript", ""),
                    }

                except Exception as e:
                    return {
                        "success": False,
                        "error": str(e),
                        "mode": mode.mode,
                        "hypothesis": hypothesis.label,
                        "persona_variant": persona_variant,
                    }

    async def process_interviews_concurrently(
        self,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        personas: List[Dict],
        run_timestamp: str,
    ) -> List[Dict]:
        """Process multiple interviews concurrently."""
        tasks = []

        for i, persona in enumerate(personas):
            task = self.process_interview_async(
                config, mode, hypothesis, persona, i, run_timestamp
            )
            tasks.append(task)

        # Execute all interviews concurrently
        results = await asyncio.gather(*tasks, return_exceptions=True)

        # Handle exceptions
        processed_results = []
        for result in results:
            if isinstance(result, Exception):
                processed_results.append(
                    {
                        "success": False,
                        "error": str(result),
                        "mode": mode.mode,
                        "hypothesis": hypothesis.label,
                    }
                )
            else:
                processed_results.append(result)

        return processed_results

    def _generate_interview_prompt_async(
        self,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona: Dict,
        persona_variant: int,
        run_timestamp: str,
    ) -> str:
        """Generate interview prompt for async processing."""
        return PromptGenerator.generate_interview_prompt(
            config, mode, hypothesis, persona_variant, run_timestamp, persona
        )

    async def _call_openai_async(self, prompt: str, model: str) -> str:
        """Call OpenAI API asynchronously."""
        if not self.session:
            raise RuntimeError("Session not initialized. Use async context manager.")

        headers = {
            "Authorization": f"Bearer {self.api_key}",
            "Content-Type": "application/json",
        }

        data = {
            "model": model,
            "messages": [{"role": "user", "content": prompt}],
            "max_tokens": 2000,
            "temperature": 0.7,
        }

        async with self.session.post(
            "https://api.openai.com/v1/chat/completions", headers=headers, json=data
        ) as response:
            if response.status == 200:
                result = await response.json()
                return result["choices"][0]["message"]["content"]
            else:
                error_text = await response.text()
                raise Exception(f"OpenAI API error: {response.status} - {error_text}")

    def _parse_markdown_response(self, response: str) -> Dict:
        """Parse markdown response (reuse existing logic)."""
        # This would reuse the existing parsing logic
        return {
            "insights": response,
            "persona": "Generated persona",
            "interview_transcript": "Interview transcript",
        }

    def _parse_json_response(self, response: str) -> Dict:
        """Parse JSON response (reuse existing logic)."""
        try:
            return json.loads(response)
        except json.JSONDecodeError:
            return {
                "insights": response,
                "persona": "Generated persona",
                "interview_transcript": "Interview transcript",
            }


class AsyncInsightAggregator:
    """
    Asynchronous insight aggregator for concurrent insight processing.
    """

    def __init__(self):
        """Initialize the async insight aggregator."""
        pass

    async def aggregate_insights_async(self, insights: List[Dict]) -> Dict:
        """Aggregate insights asynchronously."""
        # Process insights concurrently
        tasks = [self._process_single_insight_async(insight) for insight in insights]
        processed_insights = await asyncio.gather(*tasks)

        # Aggregate results
        return self._aggregate_processed_insights(processed_insights)

    async def _process_single_insight_async(self, insight: Dict) -> Dict:
        """Process a single insight asynchronously."""
        return InsightExtractor.process_insight(insight)


class LLMInsightAnalyzer:
    """
    LLM-driven insight analyzer that provides richer, more nuanced analysis
    than regex-based extraction.
    """

    def __init__(self, api_key: Optional[str] = None):
        """Initialize the LLM insight analyzer."""
        self.api_key = api_key or os.getenv("OPENAI_API_KEY")
        if not self.api_key:
            raise ValueError("OpenAI API key is required")

        openai.api_key = self.api_key

    async def analyze_single_insight_async(self, insight: Dict) -> Dict:
        """Analyze a single insight using LLM for richer understanding."""
        insight_text = insight.get("insights", "")

        if not insight_text.strip():
            return {
                "aligned": False,
                "pain_points": [],
                "desired_outcomes": [],
                "summary": "No insight content provided",
                "error": "Empty insight text",
            }

        try:
            # Create LLM prompt for insight analysis
            prompt = f"""Analyze this interview insight and extract structured information:

{insight_text}

Please provide a JSON response with the following structure:
{{
    "aligned": true/false,
    "alignment_reasoning": "explanation of why aligned or not",
    "confidence": 0.0-1.0,
    "pain_points": ["list", "of", "pain", "points"],
    "pain_points_severity": {{"pain_point": "high/medium/low"}},
    "desired_outcomes": ["list", "of", "desired", "outcomes"],
    "outcomes_priority": {{"outcome": "high/medium/low"}},
    "summary": "conversational summary of the key findings",
    "recommendations": ["list", "of", "actionable", "recommendations"]
}}

Focus on understanding the nuance and context of the persona's experience."""

            # Call LLM for analysis
            response = await self._call_openai_async(prompt, "gpt-4o-mini")

            # Parse JSON response
            try:
                result = json.loads(response)
                return {
                    "aligned": result.get("aligned", False),
                    "pain_points": result.get("pain_points", []),
                    "desired_outcomes": result.get("desired_outcomes", []),
                    "summary": result.get("summary", ""),
                    "alignment_reasoning": result.get("alignment_reasoning", ""),
                    "confidence": result.get("confidence", 0.5),
                    "recommendations": result.get("recommendations", []),
                }
            except json.JSONDecodeError:
                # Fallback to regex-based extraction if LLM response is malformed
                return await self._fallback_analysis(insight_text)

        except Exception as e:
            # Fallback to regex-based extraction on error
            return await self._fallback_analysis(insight_text)

    async def analyze_multiple_insights_async(self, insights: List[Dict]) -> List[Dict]:
        """Analyze multiple insights concurrently using LLM."""
        tasks = [self.analyze_single_insight_async(insight) for insight in insights]
        return await asyncio.gather(*tasks, return_exceptions=True)

    async def extract_alignment_with_context_async(self, insight_text: str) -> Dict:
        """Extract alignment with context using LLM."""
        prompt = f"""Analyze this insight text and determine if the persona's needs align with our hypothesis:

{insight_text}

Provide a JSON response:
{{
    "aligned": true/false,
    "reasoning": "detailed explanation of alignment",
    "confidence": 0.0-1.0,
    "key_factors": ["list", "of", "key", "factors"]
}}"""

        try:
            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            result = json.loads(response)
            return result
        except Exception as e:
            return {
                "aligned": False,
                "reasoning": f"Error in analysis: {str(e)}",
                "confidence": 0.0,
                "key_factors": [],
            }

    async def extract_pain_points_with_nuance_async(self, insight_text: str) -> Dict:
        """Extract pain points with nuance using LLM."""
        prompt = f"""Analyze this insight text and extract pain points with context:

{insight_text}

Provide a JSON response:
{{
    "pain_points": ["list", "of", "pain", "points"],
    "severity": {{"pain_point": "high/medium/low"}},
    "context": "explanation of the context around these pain points",
    "emotional_impact": "description of emotional impact"
}}"""

        try:
            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            result = json.loads(response)
            return result
        except Exception as e:
            return {
                "pain_points": [],
                "severity": {},
                "context": f"Error in analysis: {str(e)}",
                "emotional_impact": "",
            }

    async def extract_desired_outcomes_with_context_async(
        self, insight_text: str
    ) -> Dict:
        """Extract desired outcomes with context using LLM."""
        prompt = f"""Analyze this insight text and extract desired outcomes with context:

{insight_text}

Provide a JSON response:
{{
    "desired_outcomes": ["list", "of", "desired", "outcomes"],
    "priority": {{"outcome": "high/medium/low"}},
    "feasibility": {{"outcome": "high/medium/low"}},
    "context": "explanation of the context around these outcomes"
}}"""

        try:
            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            result = json.loads(response)
            return result
        except Exception as e:
            return {
                "desired_outcomes": [],
                "priority": {},
                "feasibility": {},
                "context": f"Error in analysis: {str(e)}",
            }

    async def generate_insight_summary_async(self, insight: Dict) -> str:
        """Generate conversational insight summary using LLM."""
        prompt = f"""Create a conversational summary of this insight analysis:

{json.dumps(insight, indent=2)}

Write a clear, conversational summary that explains the key findings and their implications. 
Focus on making it readable and actionable for product development."""

        try:
            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response
        except Exception as e:
            return f"Error generating summary: {str(e)}"

    async def _call_openai_async(self, prompt: str, model: str) -> str:
        """Call OpenAI API asynchronously."""
        try:
            response = openai.chat.completions.create(
                model=model,
                messages=[
                    {
                        "role": "system",
                        "content": "You are an expert research analyst specializing in user insights and product development. Provide clear, structured analysis in JSON format when requested.",
                    },
                    {"role": "user", "content": prompt},
                ],
                max_tokens=2000,
                temperature=0.3,
            )
            return response.choices[0].message.content
        except Exception as e:
            raise Exception(f"OpenAI API call failed: {str(e)}")

    async def _fallback_analysis(self, insight_text: str) -> Dict:
        """Fallback to regex-based analysis if LLM fails."""
        # Use the existing InsightExtractor as fallback
        return InsightExtractor.process_insight({"insights": insight_text})


class LLMReportGenerator:
    """
    LLM-driven report generator that creates conversational, coherent reports
    by reading existing documents and appending insights intelligently.
    """

    def __init__(self, api_key: Optional[str] = None):
        """Initialize the LLM report generator."""
        self.api_key = api_key or os.getenv("OPENAI_API_KEY")
        if not self.api_key:
            raise ValueError("OpenAI API key is required")

        openai.api_key = self.api_key

    async def generate_master_report_async(
        self, insights: List[Dict], project_name: str
    ) -> str:
        """Generate a master report using LLM for conversational analysis."""
        if not insights:
            return self._generate_empty_report(project_name)

        try:
            # Create LLM prompt for master report generation
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Create a comprehensive, conversational master report for the project "{project_name}" based on these insights:

{insights_summary}

The report should be written in clear, conversational English that makes it maximally usable for product development. Include:

1. Executive Summary - High-level findings and recommendations
2. Key Insights - Detailed analysis of the most important findings
3. Pain Points Analysis - Understanding of user challenges
4. Desired Outcomes - What users want to achieve
5. Recommendations - Actionable next steps
6. Product Implications - How this affects product development

Write in a conversational tone that reads like expert analysis from a human researcher."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating master report: {str(e)}"

    async def append_insights_to_existing_report_async(
        self, existing_report: str, new_insights: List[Dict]
    ) -> str:
        """Append new insights to existing report using LLM."""
        if not new_insights:
            return existing_report

        try:
            new_insights_summary = self._prepare_insights_summary(new_insights)

            prompt = f"""Read this existing master report and intelligently append new insights:

EXISTING REPORT:
{existing_report}

NEW INSIGHTS TO APPEND:
{new_insights_summary}

Please update the existing report by:
1. Reading and understanding the existing content
2. Integrating the new insights naturally
3. Updating relevant sections with new findings
4. Maintaining the conversational tone
5. Adding new sections if needed

Return the complete updated report."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"{existing_report}\n\nError appending insights: {str(e)}"

    async def generate_conversational_analysis_async(self, insights: List[Dict]) -> str:
        """Generate conversational analysis of insights."""
        if not insights:
            return "No insights available for analysis."

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Analyze these user research insights and provide a conversational analysis:

{insights_summary}

Write a clear, conversational analysis that:
- Explains the key patterns and findings
- Provides context for why these insights matter
- Suggests what these findings mean for product development
- Uses natural, readable language

Write as if you're explaining this to a colleague over coffee."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating analysis: {str(e)}"

    async def maintain_context_across_interviews_async(
        self, interview_1: List[Dict], interview_2: List[Dict]
    ) -> str:
        """Maintain context across multiple interviews using LLM."""
        try:
            interview_1_summary = self._prepare_insights_summary(interview_1)
            interview_2_summary = self._prepare_insights_summary(interview_2)

            prompt = f"""Analyze these two sets of interview insights and identify connections:

INTERVIEW SET 1:
{interview_1_summary}

INTERVIEW SET 2:
{interview_2_summary}

Please provide a conversational analysis that:
- Identifies patterns and connections between the interviews
- Explains how the findings relate to each other
- Suggests what these connections mean for product development
- Maintains context and continuity between the interviews

Write in a conversational tone that helps understand the bigger picture."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error maintaining context: {str(e)}"

    async def generate_actionable_recommendations_async(
        self, insights: List[Dict]
    ) -> str:
        """Generate actionable recommendations based on insights."""
        if not insights:
            return "No insights available for recommendations."

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Based on these user research insights, generate actionable recommendations:

{insights_summary}

Provide specific, actionable recommendations that:
- Address the key pain points identified
- Leverage the desired outcomes mentioned
- Are practical and implementable
- Include clear next steps
- Consider business and technical feasibility

Write in a conversational tone that makes the recommendations easy to understand and act upon."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating recommendations: {str(e)}"

    def _prepare_insights_summary(self, insights: List[Dict]) -> str:
        """Prepare insights for LLM processing."""
        summary_parts = []

        for i, insight in enumerate(insights, 1):
            summary_parts.append(f"Insight {i}:")
            summary_parts.append(f"- Aligned: {insight.get('aligned', 'Unknown')}")
            summary_parts.append(
                f"- Pain Points: {', '.join(insight.get('pain_points', []))}"
            )
            summary_parts.append(
                f"- Desired Outcomes: {', '.join(insight.get('desired_outcomes', []))}"
            )
            if insight.get("summary"):
                summary_parts.append(f"- Summary: {insight['summary']}")
            summary_parts.append("")

        return "\n".join(summary_parts)

    def _generate_empty_report(self, project_name: str) -> str:
        """Generate a report for when no insights are available."""
        return f"""# Master Report - {project_name}

**Generated:** {datetime.now().strftime('%Y-%m-%d %H:%M:%S')}

## No Insights Available

This report was generated without any interview insights. Please run interviews to collect data for analysis.

## Next Steps

1. Configure interview parameters
2. Run interview cycles
3. Collect and analyze insights
4. Generate comprehensive report"""

    async def _call_openai_async(self, prompt: str, model: str) -> str:
        """Call OpenAI API asynchronously."""
        try:
            response = openai.chat.completions.create(
                model=model,
                messages=[
                    {
                        "role": "system",
                        "content": "You are an expert research analyst and report writer. Create clear, conversational reports that are maximally usable for product development teams.",
                    },
                    {"role": "user", "content": prompt},
                ],
                max_tokens=4000,
                temperature=0.4,
            )
            return response.choices[0].message.content
        except Exception as e:
            raise Exception(f"OpenAI API call failed: {str(e)}")

    def _aggregate_processed_insights(self, processed_insights: List[Dict]) -> Dict:
        """Aggregate processed insights into summary."""
        total_insights = len(processed_insights)
        aligned_count = sum(1 for insight in processed_insights if insight["aligned"])

        # Collect all pain points and outcomes
        all_pain_points = []
        all_desired_outcomes = []

        for insight in processed_insights:
            all_pain_points.extend(insight["pain_points"])
            all_desired_outcomes.extend(insight["desired_outcomes"])

        # Count frequencies
        pain_point_counts = {}
        for point in all_pain_points:
            pain_point_counts[point] = pain_point_counts.get(point, 0) + 1

        outcome_counts = {}
        for outcome in all_desired_outcomes:
            outcome_counts[outcome] = outcome_counts.get(outcome, 0) + 1

        return {
            "alignment_rate": (
                aligned_count / total_insights if total_insights > 0 else 0
            ),
            "total_insights": total_insights,
            "aligned_count": aligned_count,
            "common_pain_points": sorted(
                pain_point_counts.items(), key=lambda x: x[1], reverse=True
            )[:5],
            "common_desired_outcomes": sorted(
                outcome_counts.items(), key=lambda x: x[1], reverse=True
            )[:5],
            "modes": list(set(insight["mode"] for insight in processed_insights)),
        }

    async def extract_evolution_signals_async(self, insights: List[Dict]) -> Dict:
        """Extract evolution signals asynchronously."""
        # Use the existing insight analyzer logic
        analyzer = InsightAnalyzer()
        return analyzer.extract_evolution_signals(insights)


class AsyncIterativeResearchEngine:
    """
    Asynchronous iterative research engine for concurrent processing.
    """

    def __init__(
        self,
        api_key: Optional[str] = None,
        config_dir: Optional[str] = None,
        cycles: int = 3,
        evolution_enabled: bool = True,
        max_concurrent_interviews: int = None,
        project_name: Optional[str] = None,
    ):
        """
        Initialize the async iterative research engine.

        Args:
            api_key: OpenAI API key
            config_dir: Directory containing versioned configs
            cycles: Number of iteration cycles to run
            evolution_enabled: Whether to enable automatic product evolution
            max_concurrent_interviews: Maximum concurrent interviews per cycle
            project_name: Optional project name for folder structure
        """
        # Load API key from .env if not provided
        if api_key is None:
            from dotenv import load_dotenv

            load_dotenv()
            api_key = os.getenv("OPENAI_API_KEY")

        self.api_key = api_key
        self.config_dir = config_dir
        self.cycles = cycles
        self.evolution_enabled = evolution_enabled
        self.max_concurrent_interviews = max_concurrent_interviews
        self.current_cycle = 0
        self.evolution_history = []
        self.product_evolution_engine = ProductEvolutionEngine()
        self.async_persona_generator = AsyncPersonaGenerator(api_key=self.api_key)
        self.project_name = project_name or "default_project"

        # Load initial config
        self.current_config = self._load_current_config()

        # Create project folder structure
        self._setup_project_structure()

    def _setup_project_structure(self):
        """Setup the project/config/run folder structure."""
        self.project_dir = Path("outputs") / self.project_name
        self.config_dir_path = self.project_dir / "config"
        self.runs_dir = self.project_dir / "runs"

        # Create directories
        self.project_dir.mkdir(exist_ok=True)
        self.config_dir_path.mkdir(exist_ok=True)
        self.runs_dir.mkdir(exist_ok=True)

    def _load_current_config(self) -> ProjectConfig:
        """Load the current configuration from the config directory."""
        if self.config_dir:
            # Try to find any JSON config file in the config directory
            config_dir = Path(self.config_dir)
            config_files = list(config_dir.glob("*.json"))

            if config_files:
                # Use the first config file found
                config_path = config_files[0]
                with open(config_path, "r") as f:
                    data = json.load(f)
                    config = self._dict_to_config(data)
                    # Extract project name from config if not explicitly set
                    if (
                        self.project_name == "default_project"
                        and "project_name" in data
                    ):
                        self.project_name = data["project_name"]
                    return config

        # Fallback to a default config
        return ProjectConfig(
            project_name="AsyncIterativeResearch",
            product_sketch="Default product sketch",
            interview_modes=[],
        )

    def _dict_to_config(self, data: Dict) -> ProjectConfig:
        """Convert dict to ProjectConfig with proper interview mode parsing."""
        # Create a temporary config file to use ConfigManager
        import tempfile

        with tempfile.NamedTemporaryFile(mode="w", suffix=".json", delete=False) as f:
            json.dump(data, f)
            temp_path = f.name

        try:
            return ConfigManager.load_config_from_json(temp_path)
        finally:
            import os

            os.unlink(temp_path)

    def _save_evolved_config(self, config: ProjectConfig, cycle_number: int):
        """Save evolved config to the project structure."""
        config_version = f"v{cycle_number + 1}"
        config.version = config_version

        # Clean the product sketch to remove evolution pollution
        if "Evolved to address:" in config.product_sketch:
            # Extract the original product sketch (before evolution notes)
            original_sketch = config.product_sketch.split("Evolved to address:")[
                0
            ].strip()
            config.product_sketch = original_sketch

        # Save to project config directory
        config_path = self.config_dir_path / f"ygt_config_{config_version}.json"
        config_dict = self._config_to_dict(config)

        with open(config_path, "w") as f:
            json.dump(config_dict, f, indent=2)

        # Also save as current config
        current_config_path = self.config_dir_path / "ygt_config.json"
        with open(current_config_path, "w") as f:
            json.dump(config_dict, f, indent=2)

        print(f"💾 Saved evolved config to {config_path}")

        # Create evolution log entry
        self._log_evolution(cycle_number, config_version)

    def _log_evolution(self, cycle_number: int, config_version: str):
        """Log evolution details to evolution_log.md."""
        evolution_log_path = self.project_dir / "evolution_log.md"

        # Create or append to evolution log
        timestamp = datetime.now().strftime("%Y-%m-%d %H:%M:%S")

        log_entry = f"""
## Cycle {cycle_number} Evolution - {timestamp}

**Config Version:** {config_version}

**Evolution Details:**
- Cycle completed successfully
- Config evolved to {config_version}
- Timestamp: {timestamp}

---
"""

        if evolution_log_path.exists():
            # Append to existing log
            with open(evolution_log_path, "a") as f:
                f.write(log_entry)
        else:
            # Create new log
            with open(evolution_log_path, "w") as f:
                f.write(f"# Evolution Log - {self.project_name}\n\n{log_entry}")

    def _config_to_dict(self, config: ProjectConfig) -> Dict:
        """Convert ProjectConfig to dict."""
        return ConfigManager.config_to_dict(config)

    async def _run_single_cycle_async(self) -> Dict:
        """Run a single iteration cycle asynchronously."""
        self.current_cycle += 1
        cycle_start = datetime.now()

        print(f"\n🔄 Starting Async Cycle {self.current_cycle}/{self.cycles}")
        print(
            f"📋 Current config: {self.current_config.project_name} v{self.current_config.version}"
        )

        try:
            # Step 1: Generate unique personas for this cycle
            print("👥 Generating unique personas asynchronously...")
            total_personas = sum(
                mode.persona_count for mode in self.current_config.interview_modes
            )
            personas = await self.async_persona_generator.generate_personas_async(
                total_personas, self.current_cycle
            )
            print(f"✅ Generated {len(personas)} unique personas concurrently")

            # Step 2: Process interviews asynchronously
            print("🎤 Processing interviews asynchronously...")
            async with AsyncInterviewProcessor(
                api_key=self.api_key,
                max_concurrent=self.max_concurrent_interviews,
                rate_limit_per_minute=None,  # No rate limiting - let OpenAI handle it
            ) as processor:
                all_results = []
                all_tasks = []

                # Create all interview tasks concurrently
                persona_index = 0
                for mode in self.current_config.interview_modes:
                    for hypothesis in mode.problem_hypotheses:
                        mode_personas = personas[
                            persona_index : persona_index + mode.persona_count
                        ]
                        persona_index += mode.persona_count

                        task = processor.process_interviews_concurrently(
                            self.current_config,
                            mode,
                            hypothesis,
                            mode_personas,
                            datetime.now().strftime("%Y%m%d_%H%M%S"),
                        )
                        all_tasks.append(task)

                # Execute all interview tasks concurrently
                all_results_lists = await asyncio.gather(
                    *all_tasks, return_exceptions=True
                )

                # Flatten results
                for results_list in all_results_lists:
                    if isinstance(results_list, Exception):
                        all_results.append(
                            {
                                "success": False,
                                "error": str(results_list),
                            }
                        )
                    else:
                        all_results.extend(results_list)

            # Step 3: Aggregate insights asynchronously
            print("📊 Aggregating insights asynchronously...")
            aggregator = AsyncInsightAggregator()
            aggregated = await aggregator.aggregate_insights_async(all_results)

            # Step 4: Evolve config if enabled (happens with each cycle)
            evolved_config = None
            evolution_signals = None

            if self.evolution_enabled:
                print(f"🔄 Evolving configuration after cycle {self.current_cycle}...")
                evolution_signals = await aggregator.extract_evolution_signals_async(
                    all_results
                )

                # Generate new product sketch
                new_sketch = self.product_evolution_engine.generate_new_product_sketch(
                    self.current_config.product_sketch, evolution_signals
                )

                # Create new hypotheses
                new_hypotheses = self.product_evolution_engine.create_new_hypotheses(
                    evolution_signals
                )

                # Create evolved config
                evolved_config = ProjectConfig(
                    project_name=self.current_config.project_name,
                    llm_model=self.current_config.llm_model,
                    product_sketch=new_sketch,
                    interview_modes=self.current_config.interview_modes,
                    output_format=self.current_config.output_format,
                    version=f"v{self.current_cycle + 1}",
                )

                # Update hypotheses in the first mode (simplified approach)
                if evolved_config.interview_modes and new_hypotheses:
                    evolved_config.interview_modes[0].problem_hypotheses = (
                        new_hypotheses
                    )

                # Record evolution
                self.product_evolution_engine.record_evolution(
                    self.current_config,
                    evolved_config,
                    {
                        "reason": f"Async Cycle {self.current_cycle} insights",
                        "signals": evolution_signals,
                        "cycle_number": self.current_cycle,
                    },
                )

                # Save evolved config to project structure
                self._save_evolved_config(evolved_config, self.current_cycle)

                # Update current config for next cycle
                self.current_config = evolved_config

                print(f"✅ Evolved config to v{evolved_config.version}")
                print(
                    f"📈 Evolution signals: {len(evolution_signals.get('misaligned_hypotheses', []))} misaligned hypotheses"
                )

            cycle_duration = (datetime.now() - cycle_start).total_seconds()

            return {
                "cycle_number": self.current_cycle,
                "success": True,
                "insights_count": len(all_results),
                "alignment_rate": aggregated.get("alignment_rate", 0.0),
                "duration": cycle_duration,
                "all_insights": all_results,
                "personas_generated": total_personas,
                "config_evolved": evolved_config is not None,
                "evolution_signals": evolution_signals,
                "config_version": self.current_config.version,
                "concurrent_interviews": self.max_concurrent_interviews,
            }

        except Exception as e:
            cycle_duration = (datetime.now() - cycle_start).total_seconds()
            print(f"❌ Async Cycle {self.current_cycle} failed: {str(e)}")
            return {
                "cycle_number": self.current_cycle,
                "success": False,
                "error": str(e),
                "duration": cycle_duration,
                "insights_count": 0,
                "alignment_rate": 0.0,
                "personas_generated": 0,
                "config_evolved": False,
            }

    async def run_iterative_research_async(self) -> List[Dict]:
        """Run the complete async iterative research process with N cycles."""
        print(f"🚀 Starting async iterative research with {self.cycles} cycles")
        print(f"📁 Project: {self.project_name}")
        print(f"🔄 Evolution enabled: {self.evolution_enabled}")
        print(f"⚡ Max concurrent interviews: {self.max_concurrent_interviews}")

        # Create run directory with timestamp
        run_timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
        run_dir = self.runs_dir / f"run_{run_timestamp}"
        run_dir.mkdir(exist_ok=True)

        results = []

        for cycle in range(self.cycles):
            # Run the complete async iteration cycle
            cycle_result = await self._run_single_cycle_async()
            results.append(cycle_result)

            # Print cycle summary
            if cycle_result["success"]:
                print(
                    f"✅ Async Cycle {cycle_result['cycle_number']} completed successfully"
                )
                print(f"   📊 Alignment: {cycle_result['alignment_rate']:.1%}")
                print(f"   👥 Personas: {cycle_result['personas_generated']}")
                print(f"   ⏱️  Duration: {cycle_result['duration']:.1f}s")
                print(
                    f"   ⚡ Concurrent: {cycle_result.get('concurrent_interviews', 'N/A')}"
                )
                if cycle_result["config_evolved"]:
                    print(f"   🔄 Config evolved to: {cycle_result['config_version']}")
            else:
                print(
                    f"❌ Async Cycle {cycle_result['cycle_number']} failed: {cycle_result.get('error', 'Unknown error')}"
                )

            # Add a separator between cycles
            if cycle < self.cycles - 1:
                print("\n" + "=" * 50 + "\n")

        # Generate master report and roadmap
        await self._generate_master_report_and_roadmap(results, run_dir)

        # Print final summary
        self._print_final_summary(results)

        return results

    async def _generate_master_report_and_roadmap(
        self, results: List[Dict], run_dir: Path
    ):
        """Generate master report and roadmap with improvements tracking."""
        successful_cycles = [r for r in results if r["success"]]

        if not successful_cycles:
            return

        # Collect all insights across cycles
        all_insights = []
        for result in successful_cycles:
            all_insights.extend(result.get("all_insights", []))

        # Generate master report with improvements tracking
        master_report = self._generate_master_report_with_improvements(
            results, all_insights
        )

        # Generate roadmap for latest config version
        roadmap = self._generate_roadmap_for_latest_config(all_insights)

        # Save reports
        master_report_path = run_dir / "master_report.md"
        roadmap_path = run_dir / "roadmap.md"

        with open(master_report_path, "w") as f:
            f.write(master_report)

        with open(roadmap_path, "w") as f:
            f.write(roadmap)

        print(f"📊 Generated master report: {master_report_path}")
        print(f"🗺️  Generated roadmap: {roadmap_path}")
        print(f"📝 Generated evolution log: {self.project_dir}/evolution_log.md")

    def _evolve_hypotheses_based_on_insights(
        self, current_hypotheses: List[ProblemHypothesis], evolution_signals: Dict
    ) -> List[ProblemHypothesis]:
        """Evolve hypotheses based on interview insights."""
        evolved_hypotheses = []

        for hypothesis in current_hypotheses:
            # Check if this hypothesis needs evolution based on signals
            needs_evolution = self._should_evolve_hypothesis(
                hypothesis, evolution_signals
            )

            if needs_evolution:
                # Create evolved hypothesis
                evolved_hypothesis = self._create_evolved_hypothesis(
                    hypothesis, evolution_signals
                )
                evolved_hypotheses.append(evolved_hypothesis)
            else:
                # Keep original hypothesis
                evolved_hypotheses.append(hypothesis)

        return evolved_hypotheses

    def _should_evolve_hypothesis(
        self, hypothesis: ProblemHypothesis, evolution_signals: Dict
    ) -> bool:
        """Determine if a hypothesis should evolve based on signals."""
        # Check for low alignment signals
        misaligned_hypotheses = evolution_signals.get("misaligned_hypotheses", [])
        if hypothesis.label in misaligned_hypotheses:
            return True

        # Check for specific insights that suggest evolution
        insights = evolution_signals.get("insights", [])
        for insight in insights:
            if "too broad" in insight.lower() or "too specific" in insight.lower():
                return True

        return False

    def _create_evolved_hypothesis(
        self, hypothesis: ProblemHypothesis, evolution_signals: Dict
    ) -> ProblemHypothesis:
        """Create an evolved version of a hypothesis based on insights."""
        # For now, create a refined version of the hypothesis
        # In a full implementation, this would use LLM to generate evolved hypotheses

        evolved_label = f"{hypothesis.label} (Refined)"
        evolved_description = f"{hypothesis.description} [Evolved based on user feedback and alignment signals]"

        return ProblemHypothesis(label=evolved_label, description=evolved_description)

    def _generate_master_report_with_improvements(
        self, results: List[Dict], all_insights: List[Dict]
    ) -> str:
        """Generate master report with plain English explanations of improvements."""
        successful_cycles = [r for r in results if r["success"]]

        report = f"# Master Report - {self.project_name}\n\n"
        report += f"**Generated:** {datetime.now().strftime('%Y-%m-%d %H:%M:%S')}\n"
        report += f"**Total Cycles:** {len(results)}\n"
        report += f"**Successful Cycles:** {len(successful_cycles)}\n\n"

        # Overall statistics
        if successful_cycles:
            total_insights = sum(r["insights_count"] for r in successful_cycles)
            total_personas = sum(r["personas_generated"] for r in successful_cycles)
            evolved_cycles = sum(1 for r in successful_cycles if r["config_evolved"])

            report += "## Overall Statistics\n\n"
            report += f"- **Total Insights:** {total_insights}\n"
            report += f"- **Total Personas:** {total_personas}\n"
            report += f"- **Config Evolutions:** {evolved_cycles}\n\n"

        # Cycle-by-cycle improvements
        report += "## Cycle-by-Cycle Improvements\n\n"

        for i, result in enumerate(successful_cycles, 1):
            report += f"### Cycle {i}\n\n"
            report += f"- **Alignment Rate:** {result['alignment_rate']:.1%}\n"
            report += f"- **Insights Generated:** {result['insights_count']}\n"
            report += f"- **Personas Used:** {result['personas_generated']}\n"
            report += f"- **Duration:** {result['duration']:.1f}s\n"

            if result["config_evolved"]:
                report += f"- **Config Evolution:** ✅ Evolved to {result['config_version']}\n"

                # Plain English explanation of changes
                evolution_signals = result.get("evolution_signals", {})
                if evolution_signals:
                    report += "\n**Key Improvements Made:**\n"

                    misaligned = evolution_signals.get("misaligned_hypotheses", [])
                    if misaligned and isinstance(misaligned, list):
                        report += (
                            f"- **Problem Areas Identified:** {', '.join(misaligned)}\n"
                        )

                    pain_points = evolution_signals.get("common_pain_points", [])
                    if pain_points and isinstance(pain_points, list):
                        report += (
                            f"- **Common Pain Points:** {', '.join(pain_points[:3])}\n"
                        )

                    priorities = evolution_signals.get("evolution_priorities", [])
                    if priorities and isinstance(priorities, list):
                        report += (
                            f"- **Evolution Priorities:** {', '.join(priorities[:3])}\n"
                        )
            else:
                report += f"- **Config Evolution:** ❌ No evolution needed\n"

            report += "\n"

        # Key insights summary
        report += "## Evolution Timeline\n\n"

        # Add detailed timeline of changes
        for i, result in enumerate(successful_cycles, 1):
            report += f"### Cycle {i} Changes\n\n"
            report += f"- **Alignment Rate:** {result['alignment_rate']:.1%}\n"
            report += f"- **Duration:** {result['duration']:.1f}s\n"

            if result.get("config_evolved"):
                report += f"- **Config Evolution:** ✅ {result.get('config_version', 'Unknown')}\n"

                # Add hypothesis changes if available
                evolution_signals = result.get("evolution_signals", {})
                if evolution_signals:
                    report += f"- **Evolution Signals:** {len(evolution_signals)} signals detected\n"

                    # Track hypothesis changes
                    if "hypothesis_changes" in evolution_signals:
                        report += "**Hypothesis Changes:**\n"
                        for change in evolution_signals["hypothesis_changes"]:
                            report += f"  - {change}\n"
            else:
                report += "- **Config Evolution:** ❌ No changes needed\n"

            report += "\n"

        # Add alignment trend analysis
        alignment_rates = [r["alignment_rate"] for r in successful_cycles]
        if len(alignment_rates) > 1:
            trend = (
                "↗️ Improving"
                if alignment_rates[-1] > alignment_rates[0]
                else "↘️ Declining"
            )
            report += f"**Alignment Trend:** {trend} ({alignment_rates[0]:.1%} → {alignment_rates[-1]:.1%})\n\n"

        report += "## Key Insights Summary\n\n"

        # Analyze insights for patterns
        insight_texts = [insight.get("insights", "") for insight in all_insights]

        # Count alignment mentions
        aligned_count = sum(
            1 for text in insight_texts if "aligned? yes" in text.lower()
        )
        misaligned_count = sum(
            1 for text in insight_texts if "aligned? no" in text.lower()
        )

        report += f"- **Aligned Hypotheses:** {aligned_count}\n"
        report += f"- **Misaligned Hypotheses:** {misaligned_count}\n"

        if insight_texts:
            report += f"- **Total Interview Responses:** {len(insight_texts)}\n"

        report += "\n"

        return report

    def _generate_roadmap_for_latest_config(self, all_insights: List[Dict]) -> str:
        """Generate roadmap for the most recent config version."""
        roadmap = f"# Product Roadmap - {self.project_name}\n\n"
        roadmap += f"**Generated:** {datetime.now().strftime('%Y-%m-%d %H:%M:%S')}\n"
        roadmap += f"**Current Config Version:** {self.current_config.version}\n\n"

        # Extract feature suggestions from insights
        feature_suggestions = []
        pain_points = []

        for insight in all_insights:
            processed_insight = InsightExtractor.process_insight(insight)
            pain_points.extend(processed_insight["pain_points"])
            feature_suggestions.extend(processed_insight["desired_outcomes"])

        # Count and rank features
        feature_counts = {}
        for feature in feature_suggestions:
            if feature:
                feature_counts[feature] = feature_counts.get(feature, 0) + 1

        pain_point_counts = {}
        for point in pain_points:
            if point:
                pain_point_counts[point] = pain_point_counts.get(point, 0) + 1

        roadmap += "## High Priority Features\n\n"

        # Top features by frequency
        top_features = sorted(feature_counts.items(), key=lambda x: x[1], reverse=True)[
            :5
        ]
        for feature, count in top_features:
            roadmap += f"- **{feature}** (mentioned {count} times)\n"

        roadmap += "\n## Pain Points to Address\n\n"

        # Top pain points by frequency
        top_pain_points = sorted(
            pain_point_counts.items(), key=lambda x: x[1], reverse=True
        )[:5]
        for point, count in top_pain_points:
            roadmap += f"- **{point}** (mentioned {count} times)\n"

        roadmap += "\n## Implementation Notes\n\n"
        roadmap += (
            "- Features are ranked by frequency of mention across all interviews\n"
        )
        roadmap += "- Pain points indicate areas requiring immediate attention\n"
        roadmap += "- This roadmap is based on the latest config version and all collected insights\n"

        return roadmap

    def _print_final_summary(self, results: List[Dict]):
        """Print a summary of all async cycles."""
        successful_cycles = [r for r in results if r["success"]]
        failed_cycles = [r for r in results if not r["success"]]

        print("\n" + "=" * 60)
        print("🎯 ASYNC ITERATIVE RESEARCH SUMMARY")
        print("=" * 60)

        print(f"📊 Total Cycles: {len(results)}")
        print(f"✅ Successful: {len(successful_cycles)}")
        print(f"❌ Failed: {len(failed_cycles)}")

        if successful_cycles:
            avg_alignment = sum(r["alignment_rate"] for r in successful_cycles) / len(
                successful_cycles
            )
            total_insights = sum(r["insights_count"] for r in successful_cycles)
            total_personas = sum(r["personas_generated"] for r in successful_cycles)
            total_duration = sum(r["duration"] for r in successful_cycles)
            evolved_cycles = sum(1 for r in successful_cycles if r["config_evolved"])

            print(f"📈 Average Alignment: {avg_alignment:.1%}")
            print(f"💡 Total Insights: {total_insights}")
            print(f"👥 Total Personas: {total_personas}")
            print(f"⏱️  Total Duration: {total_duration:.1f}s")
            print(f"🔄 Config Evolutions: {evolved_cycles}")
            print(f"⚡ Max Concurrent: {self.max_concurrent_interviews}")

            # Show alignment improvement
            if len(successful_cycles) > 1:
                first_alignment = successful_cycles[0]["alignment_rate"]
                last_alignment = successful_cycles[-1]["alignment_rate"]
                improvement = last_alignment - first_alignment
                print(f"📈 Alignment Improvement: {improvement:+.1%}")

        print(f"📁 Project Directory: {self.project_dir}")
        print(f"📊 Reports: {self.runs_dir}")


class LLMInterviewEngine:
    """
    Main engine for running LLM-to-LLM research interviews.

    This class provides functionality for:
    - Interactive CLI for project management
    - Multi-persona interview generation
    - Structured interview execution with three-phase process
    - Master report aggregation and analysis
    - Robust error handling with exponential backoff
    - Version-aware iterative research with design logs and resonance analysis

    Example:
        engine = LLMInterviewEngine()
        engine.run_cli()
    """

    def __init__(self, api_key: Optional[str] = None, config_dir: Optional[str] = None):
        """
        Initialize the LLM Interview Engine.

        Args:
            api_key (Optional[str]): OpenAI API key. If None, will try to load from environment.
            config_dir (Optional[str]): Directory containing versioned configs (e.g., "config/v2/")
        """
        load_dotenv()

        # Set up OpenAI client
        self.api_key = api_key or os.getenv("OPENAI_API_KEY")
        if not self.api_key:
            raise ValueError(
                "OpenAI API key is required. Set OPENAI_API_KEY environment variable or pass api_key parameter."
            )

        openai.api_key = self.api_key

        # Set up output directory
        self.output_dir = Path("outputs")
        self.output_dir.mkdir(exist_ok=True)

        # Version-aware configuration
        self.config_dir = config_dir
        if self.config_dir:
            self.config_path = Path(self.config_dir)
            if not self.config_path.exists():
                raise ValueError(f"Config directory {self.config_dir} does not exist")
        else:
            self.config_path = None

    def run_cli(self):
        """Run the interactive CLI for the interview engine."""
        print("🤖 LLM Interview Engine - Version-Aware Iterative Research")
        print("=" * 60)

        if self.config_dir:
            print(f"📁 Using config directory: {self.config_dir}")
            self._run_versioned_mode()
        else:
            print("🔄 Running in legacy mode (no version directory specified)")
            self._run_legacy_mode()

    def _run_versioned_mode(self):
        """Run the engine in version-aware mode with config directory."""
        try:
            # Load config from the specified directory
            config_file = self.config_path / "ygt_config.json"
            if not config_file.exists():
                print(f"❌ Config file not found: {config_file}")
                return

            config = self._load_json_config(str(config_file))
            config.version = (
                self.config_path.name
            )  # Extract version from directory name

            print(f"✅ Loaded config for version: {config.version}")
            print(f"📋 Project: {config.project_name}")
            print(f"🤖 Model: {config.llm_model}")
            print(f"📝 Output Format: {config.output_format}")

            # Show project summary
            self._show_project_summary(config)

            # Run interviews
            run_results = self._run_interviews(config)

            # Update design log with insights
            if run_results and "all_insights" in run_results:
                self._update_design_log(
                    config, run_results.get("run_metadata"), run_results["all_insights"]
                )

                # Add resonance analysis to master report
                project_dir = Path("outputs") / config.version / config.project_name
                master_report_path = project_dir / "master_report.md"
                if master_report_path.exists():
                    self._add_resonance_analysis_to_master_report(
                        master_report_path, config, run_results["all_insights"]
                    )
            else:
                self._update_design_log(config)

        except Exception as e:
            logger.error(f"Error in versioned mode: {e}")
            print(f"❌ Error: {e}")

    def _run_legacy_mode(self):
        """Run the engine in legacy mode with interactive CLI."""
        print("\nChoose an option:")
        print("1. Create new project")
        print("2. Load existing project")
        print("3. Load from JSON config")
        print("4. Create test config")

        choice = input("\nEnter your choice (1-4): ").strip()

        if choice == "1":
            config = self._create_new_project()
        elif choice == "2":
            config = self._load_existing_project()
        elif choice == "3":
            config_path = input("Enter path to JSON config file: ").strip()
            config = self._load_json_config(config_path)
        elif choice == "4":
            config = self._create_test_config()
        else:
            print("Invalid choice. Exiting.")
            return

        self._show_project_summary(config)
        action = self._prompt_project_action()

        if action == "run":
            self._run_interviews(config)
        elif action == "modify":
            config = self._modify_config(config)
            self._save_config(config)
            self._run_interviews(config)
        elif action == "variant":
            config = self._create_variant(config)
            self._save_config(config)
            self._run_interviews(config)
        elif action == "same":
            self._run_interviews(config)

    def _prompt_project_choice(self) -> str:
        """Prompt user to choose between new, existing project, or JSON config input"""
        while True:
            choice = (
                input(
                    "Run interviews on an existing project, start a new one, or paste JSON config? (existing/new/json): "
                )
                .strip()
                .lower()
            )
            if choice in ["existing", "new", "json"]:
                return choice
            print("Please enter 'existing', 'new', or 'json'")

    def _create_new_project(self) -> ProjectConfig:
        """Interactive creation of a new project"""
        print("\n📝 Creating New Project")
        print("-" * 30)

        project_name = input("Project name: ").strip()
        if not project_name:
            raise ValueError("Project name is required")

        llm_model = input("LLM model (default: gpt-4o-mini): ").strip() or "gpt-4o-mini"

        print("\nProduct sketch (multi-line, press Enter twice to finish):")
        product_sketch_lines = []
        while True:
            line = input()
            if line == "" and product_sketch_lines and product_sketch_lines[-1] == "":
                break
            product_sketch_lines.append(line)
        product_sketch = "\n".join(product_sketch_lines[:-1])  # Remove last empty line

        output_format = (
            input("Output format (markdown/json, default: markdown): ").strip()
            or "markdown"
        )
        if output_format not in ["markdown", "json"]:
            raise ValueError("Output format must be 'markdown' or 'json'")

        # Collect interview modes and hypotheses
        interview_modes = []
        while True:
            mode = input("\nInterview mode (or 'done' to finish): ").strip()
            if mode.lower() == "done":
                break

            persona_count = input(f"Persona count for '{mode}' (default: 3): ").strip()
            persona_count = int(persona_count) if persona_count else 3

            problem_hypotheses = []
            print(f"\nProblem hypotheses for '{mode}':")
            while True:
                label = input("Hypothesis label (or 'done' to finish): ").strip()
                if label.lower() == "done":
                    break

                description = input("Hypothesis description: ").strip()
                if not description:
                    print("Description is required")
                    continue

                problem_hypotheses.append(
                    ProblemHypothesis(label=label, description=description)
                )

            interview_modes.append(
                InterviewMode(
                    mode=mode,
                    persona_count=persona_count,
                    problem_hypotheses=problem_hypotheses,
                )
            )

        config = ProjectConfig(
            project_name=project_name,
            llm_model=llm_model,
            product_sketch=product_sketch,
            interview_modes=interview_modes,
            output_format=output_format,
        )

        # Save config
        self._save_config(config)

        return config

    def _load_json_config(self, config_path: str) -> ProjectConfig:
        """Load configuration from JSON input"""
        print(f"\n📋 Loading Configuration from {config_path}")
        print("-" * 40)
        print(f"Loading config from: {config_path}")

        try:
            with open(config_path, "r") as f:
                config_data = json.load(f)
            config = self._dict_to_config(config_data)

            # Validate required fields
            if not config.project_name:
                raise ValueError("Project name is required in JSON config")

            print(
                f"\n✅ Successfully loaded configuration for project: {config.project_name}"
            )

            # Show summary
            self._show_project_summary(config)

            # Save config
            self._save_config(config)

            return config

        except json.JSONDecodeError as e:
            print(f"❌ Invalid JSON format: {e}")
            print("Please check your JSON syntax and try again.")
            return self._create_new_project()
        except ValueError as e:
            print(f"❌ Configuration error: {e}")
            print("Please check your configuration and try again.")
            return self._create_new_project()
        except Exception as e:
            print(f"❌ Unexpected error loading JSON config: {e}")
            print("Please check your configuration and try again.")
            return self._create_new_project()

    def _load_existing_project(self) -> ProjectConfig:
        """Load an existing project configuration"""
        print("\n📁 Loading Existing Project")
        print("-" * 30)

        # Find existing projects
        project_dirs = [d for d in self.output_dir.iterdir() if d.is_dir()]

        if not project_dirs:
            print("No existing projects found. Creating new project...")
            return self._create_new_project()

        print("Existing projects:")
        for i, project_dir in enumerate(project_dirs, 1):
            print(f"{i}. {project_dir.name}")

        while True:
            try:
                choice = int(input(f"\nSelect project (1-{len(project_dirs)}): ")) - 1
                if 0 <= choice < len(project_dirs):
                    project_dir = project_dirs[choice]
                    break
                print(f"Please enter a number between 1 and {len(project_dirs)}")
            except ValueError:
                print("Please enter a valid number")

        config_path = project_dir / "config.json"
        if not config_path.exists():
            print(f"Config file not found in {project_dir}. Creating new project...")
            return self._create_new_project()

        with open(config_path, "r") as f:
            config_data = json.load(f)

        # Convert back to dataclass objects
        config = self._dict_to_config(config_data)

        # Show summary
        self._show_project_summary(config)

        # Ask what to do
        action = self._prompt_project_action()
        if action == "modify":
            config = self._modify_config(config)
        elif action == "variant":
            config = self._create_variant(config)

        return config

    def _show_project_summary(self, config: ProjectConfig):
        """Show summary of existing project"""
        print(f"\n📊 Project Summary: {config.project_name}")
        print("-" * 40)
        print(f"Model: {config.llm_model}")
        print(f"Output format: {config.output_format}")
        print(f"Interview modes: {len(config.interview_modes)}")

        total_interviews = sum(
            mode.persona_count * len(mode.problem_hypotheses)
            for mode in config.interview_modes
        )
        print(f"Total interviews: {total_interviews}")

        # Try to load master report
        master_report_path = self.output_dir / config.project_name / "master_report.md"
        if master_report_path.exists():
            print(f"Master report exists: {master_report_path}")

    def _prompt_project_action(self) -> str:
        """Prompt user for action on existing project"""
        while True:
            action = input("\nAction: reuse/modify/variant? ").strip().lower()
            if action in ["reuse", "modify", "variant"]:
                return action
            print("Please enter 'reuse', 'modify', or 'variant'")

    def _modify_config(self, config: ProjectConfig) -> ProjectConfig:
        """Modify existing configuration"""
        print("\n🔧 Modifying Configuration")
        print("-" * 30)

        # For now, just return the original config
        # TODO: Implement interactive modification
        return config

    def _create_variant(self, config: ProjectConfig) -> ProjectConfig:
        """Create a variant of existing configuration"""
        print("\n🔄 Creating Project Variant")
        print("-" * 30)

        variant_name = input(
            f"Variant name (default: {config.project_name}_variant): "
        ).strip()
        if not variant_name:
            variant_name = f"{config.project_name}_variant"

        config.project_name = variant_name
        return config

    def _save_config(self, config: ProjectConfig):
        """Save project configuration"""
        project_dir = self.output_dir / config.project_name
        project_dir.mkdir(exist_ok=True)

        config_path = project_dir / "config.json"
        with open(config_path, "w") as f:
            json.dump(self._config_to_dict(config), f, indent=2)

        print(f"✅ Configuration saved to {config_path}")

    def _config_to_dict(self, config: ProjectConfig) -> Dict:
        """Convert config to dictionary for JSON serialization"""
        data = asdict(config)
        # Convert InterviewMode objects
        data["interview_modes"] = []
        for mode in config.interview_modes:
            mode_data = asdict(mode)
            mode_data["problem_hypotheses"] = [
                asdict(h) for h in mode.problem_hypotheses
            ]
            data["interview_modes"].append(mode_data)
        return data

    def _dict_to_config(self, data: Dict) -> ProjectConfig:
        """Convert dictionary back to config object"""
        # Convert problem hypotheses and interview modes
        for mode_data in data["interview_modes"]:
            mode_data["problem_hypotheses"] = [
                ProblemHypothesis(**h) for h in mode_data["problem_hypotheses"]
            ]

        # Create InterviewMode objects
        interview_modes = []
        for mode_data in data["interview_modes"]:
            interview_modes.append(InterviewMode(**mode_data))

        # Create ProjectConfig with converted objects
        config_data = data.copy()
        config_data["interview_modes"] = interview_modes

        return ProjectConfig(**config_data)

    def _run_interviews(self, config: ProjectConfig):
        """Run the interview simulations"""
        print(f"\n🚀 Running Interviews for {config.project_name}")
        print("=" * 50)

        total_interviews = sum(
            mode.persona_count * len(mode.problem_hypotheses)
            for mode in config.interview_modes
        )

        print(f"Total interviews to run: {total_interviews}")
        confirm = input("Proceed? (y/n): ").strip().lower()
        if confirm != "y":
            print("Interview run cancelled.")
            return

        # Create version-aware project directory and run-specific subdirectory
        if self.config_dir:
            # Version-aware mode: use versioned output structure
            project_dir = Path("outputs") / config.version / config.project_name
        else:
            # Legacy mode: use original structure
            project_dir = Path("outputs") / config.project_name

        project_dir.mkdir(parents=True, exist_ok=True)

        run_timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
        run_dir = project_dir / f"run_{run_timestamp}"
        run_dir.mkdir(exist_ok=True)

        # Initialize master report and roadmap paths (at project level)
        master_report_path = project_dir / "master_report.md"
        roadmap_path = project_dir / "roadmap.md"

        run_metadata = {
            "timestamp": datetime.now().isoformat(),
            "model": config.llm_model,
            "modes": [mode.mode for mode in config.interview_modes],
            "total_interviews": total_interviews,
            "run_timestamp": run_timestamp,
        }

        # Run interviews
        completed_interviews = 0
        failed_interviews = []
        all_insights = []

        for mode in config.interview_modes:
            for hypothesis in mode.problem_hypotheses:
                print(
                    f"\n📝 Running interviews for mode: {mode.mode}, hypothesis: {hypothesis.label}"
                )

                for persona_variant in range(1, mode.persona_count + 1):
                    try:
                        print(
                            f"  Persona variant {persona_variant}/{mode.persona_count}..."
                        )

                        # Generate and run interview with run-specific randomization
                        result = self._run_single_interview(
                            config, mode, hypothesis, persona_variant, run_timestamp
                        )

                        # Save results to run directory
                        self._save_interview_results(
                            run_dir, mode, hypothesis, persona_variant, result
                        )

                        # Collect insights for aggregation
                        if "insight_summary" in result:
                            all_insights.append(
                                {
                                    "mode": mode.mode,
                                    "hypothesis": hypothesis.label,
                                    "persona_variant": persona_variant,
                                    "insights": result["insight_summary"],
                                }
                            )

                        completed_interviews += 1
                        print(
                            f"    ✅ Completed ({completed_interviews}/{total_interviews})"
                        )

                    except Exception as e:
                        error_msg = f"Failed interview for {mode.mode}/{hypothesis.label}/persona_{persona_variant}: {str(e)}"
                        logger.error(error_msg)
                        failed_interviews.append(error_msg)
                        print(f"    ❌ Failed: {str(e)}")

        # Create run-specific master report
        run_master_path = run_dir / "master_report.md"
        self._create_run_master_report(
            run_master_path,
            run_metadata,
            completed_interviews,
            failed_interviews,
            all_insights,
        )

        # Update integrated master report at project level
        self._update_integrated_master_report(
            master_report_path,
            run_metadata,
            completed_interviews,
            failed_interviews,
            all_insights,
        )

        # Generate/update integrated roadmap
        self._update_integrated_roadmap(roadmap_path, all_insights, run_metadata)

        print(f"\n🎉 Interview run completed!")
        print(f"✅ Successful: {completed_interviews}")
        print(f"❌ Failed: {len(failed_interviews)}")
        print(f"📁 Results saved to: {run_dir}")
        print(f"📊 Master report updated: {master_report_path}")
        print(f"🗺️  Roadmap updated: {roadmap_path}")

        if failed_interviews:
            print("\nFailed interviews:")
            for failure in failed_interviews:
                print(f"  - {failure}")

        # Return results for version-aware mode
        return {
            "run_metadata": run_metadata,
            "all_insights": all_insights,
            "completed_interviews": completed_interviews,
            "failed_interviews": failed_interviews,
        }

    def _run_single_interview(
        self,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona_variant: int,
        run_timestamp: str,
    ) -> Dict:
        """Run a single interview simulation with run-specific randomization"""
        prompt = self._generate_interview_prompt(
            config, mode, hypothesis, persona_variant, run_timestamp
        )

        # Call OpenAI API with retry logic
        response = self._call_openai_with_retry(prompt, config.llm_model)

        # Parse response based on output format
        if config.output_format == "markdown":
            return self._parse_markdown_response(response)
        else:
            return self._parse_json_response(response)

    def _call_openai_with_retry(
        self, prompt: str, model: str, max_retries: int = 3
    ) -> str:
        """Call OpenAI API with exponential backoff retry logic"""
        for attempt in range(max_retries):
            try:
                response = openai.chat.completions.create(
                    model=model,
                    messages=[
                        {
                            "role": "system",
                            "content": "You are an expert research interviewer conducting emotionally intelligent interviews.",
                        },
                        {"role": "user", "content": prompt},
                    ],
                    max_tokens=4000,
                    temperature=0.7,
                )
                return response.choices[0].message.content

            except Exception as e:
                if attempt == max_retries - 1:
                    raise e

                wait_time = 2**attempt  # Exponential backoff
                logger.warning(
                    f"API call failed (attempt {attempt + 1}/{max_retries}), retrying in {wait_time}s: {e}"
                )
                time.sleep(wait_time)

    def _parse_markdown_response(self, response: str) -> Dict:
        """Parse markdown response into structured data"""
        sections = {"persona": "", "interview_transcript": "", "insight_summary": ""}

        current_section = None
        lines = response.split("\n")

        for line in lines:
            if line.startswith("## Persona"):
                current_section = "persona"
            elif line.startswith("## Interview Transcript"):
                current_section = "interview_transcript"
            elif line.startswith("## Insight Summary"):
                current_section = "insight_summary"
            elif current_section and line.strip():
                sections[current_section] += line + "\n"

        return sections

    def _parse_json_response(self, response: str) -> Dict:
        """Parse JSON response into structured data"""
        try:
            return json.loads(response)
        except json.JSONDecodeError:
            # Fallback to markdown parsing if JSON is malformed
            logger.warning("JSON response malformed, falling back to markdown parsing")
            return self._parse_markdown_response(response)

    def _save_interview_results(
        self,
        project_dir: Path,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona_variant: int,
        result: Dict,
    ):
        """Save interview results to files"""
        timestamp = datetime.now().strftime("%Y%m%d_%H%M%S")
        persona_dir = project_dir / f"persona_variant_{persona_variant}"
        persona_dir.mkdir(exist_ok=True)

        # Save persona
        persona_file = persona_dir / f"persona_{timestamp}.md"
        with open(persona_file, "w") as f:
            f.write(f"# Persona for {mode.mode} - {hypothesis.label}\n\n")
            f.write(result.get("persona", ""))

        # Save interview transcript
        interview_file = persona_dir / f"interview_{timestamp}.md"
        with open(interview_file, "w") as f:
            f.write(f"# Interview Transcript for {mode.mode} - {hypothesis.label}\n\n")
            f.write(result.get("interview_transcript", ""))

        # Save insights
        insights_file = persona_dir / f"insights_{timestamp}.md"
        with open(insights_file, "w") as f:
            f.write(f"# Insight Summary for {mode.mode} - {hypothesis.label}\n\n")
            f.write(result.get("insight_summary", ""))

    def _create_run_master_report(
        self,
        run_master_path: Path,
        run_metadata: Dict,
        completed_interviews: int,
        failed_interviews: List[str],
        all_insights: List[Dict],
    ):
        """Create a run-specific master report"""
        timestamp = datetime.now().strftime("%Y-%m-%d %H:%M:%S")

        content = f"""# Run Master Report

## Run: {timestamp}

**Metadata:**
- Model: {run_metadata['model']}
- Modes: {', '.join(run_metadata['modes'])}
- Total Interviews: {run_metadata['total_interviews']}
- Completed: {completed_interviews}
- Failed: {len(failed_interviews)}
- Run Directory: {run_metadata['run_timestamp']}

"""
        if failed_interviews:
            content += "**Failed Interviews:**\n"
            for failure in failed_interviews:
                content += f"- {failure}\n"
            content += "\n"

        if all_insights:
            content += "**Key Insights Summary:**\n\n"

            # Group insights by mode
            mode_insights = {}
            for insight in all_insights:
                mode = insight["mode"]
                if mode not in mode_insights:
                    mode_insights[mode] = []
                mode_insights[mode].append(insight)

            for mode, insights in mode_insights.items():
                content += f"### {mode} Mode\n"

                # Group by hypothesis
                hypothesis_insights = {}
                for insight in insights:
                    hypothesis = insight["hypothesis"]
                    if hypothesis not in hypothesis_insights:
                        hypothesis_insights[hypothesis] = []
                    hypothesis_insights[hypothesis].append(insight)

                for hypothesis, hypothesis_insights_list in hypothesis_insights.items():
                    content += f"#### {hypothesis}\n"

                    # Extract common themes
                    solution_fits = []
                    pain_points = []
                    micro_features = []

                    for insight in hypothesis_insights_list:
                        insight_text = insight.get("insights", "")

                        # Extract solution fit
                        if "Aligned? Yes" in insight_text:
                            solution_fits.append("✅ Aligned")
                        elif "Aligned? No" in insight_text:
                            solution_fits.append("❌ Misaligned")

                        # Extract pain points
                        if "Pain Points:" in insight_text:
                            try:
                                pain_section = insight_text.split("Pain Points:")[
                                    1
                                ].split("Desired Outcomes:")[0]
                                pain_points.extend(
                                    [
                                        p.strip()
                                        for p in pain_section.split("-")
                                        if p.strip()
                                    ]
                                )
                            except IndexError:
                                pass

                        # Extract micro-features
                        if "Micro-feature Suggestions:" in insight_text:
                            try:
                                features_section = insight_text.split(
                                    "Micro-feature Suggestions:"
                                )[1]
                                micro_features.extend(
                                    [
                                        f.strip()
                                        for f in features_section.split("\n")
                                        if f.strip() and not f.startswith("-")
                                    ]
                                )
                            except IndexError:
                                pass

                    # Add summary
                    if solution_fits:
                        aligned_count = solution_fits.count("✅ Aligned")
                        total_count = len(solution_fits)
                        content += f"- **Solution Fit:** {aligned_count}/{total_count} personas aligned\n"

                    if pain_points:
                        unique_pain_points = list(set(pain_points))[
                            :3
                        ]  # Top 3 unique pain points
                        content += (
                            f"- **Key Pain Points:** {', '.join(unique_pain_points)}\n"
                        )

                    if micro_features:
                        unique_features = list(set(micro_features))[
                            :3
                        ]  # Top 3 unique features
                        content += (
                            f"- **Suggested Features:** {', '.join(unique_features)}\n"
                        )

        content += "\n**Product Sketch Critique:**\n"
        content += "- [Add critique based on insights]\n"

        content += "\n**Recommendations for Next Version:**\n"
        content += "- [Add recommendations based on insights]\n"

        content += "\n---\n\n"

        # Write to file
        with open(run_master_path, "w") as f:
            f.write(content)

    def _update_integrated_master_report(
        self,
        master_report_path: Path,
        run_metadata: Dict,
        completed_interviews: int,
        failed_interviews: List[str],
        all_insights: List[Dict],
    ):
        """Update the integrated master report with intelligent compilation of all insights"""
        # Load all existing run data from the project directory
        project_dir = master_report_path.parent
        all_runs_data = []

        # Collect data from all run directories
        for run_dir in project_dir.glob("run_*"):
            run_master_path = run_dir / "master_report.md"
            if run_master_path.exists():
                with open(run_master_path, "r") as f:
                    run_content = f.read()
                    # Extract run metadata and insights from the content
                    all_runs_data.append(
                        {"run_dir": run_dir.name, "content": run_content}
                    )

        # Add current run data
        current_run_data = {
            "run_dir": f"run_{run_metadata['run_timestamp']}",
            "insights": all_insights,
            "metadata": run_metadata,
            "completed": completed_interviews,
            "failed": failed_interviews,
        }
        all_runs_data.append(current_run_data)

        # Compile integrated insights
        integrated_insights = self._compile_integrated_insights(all_runs_data)

        # Generate comprehensive master report
        content = self._generate_comprehensive_master_report(
            integrated_insights, all_runs_data, project_dir.name
        )

        # Write the integrated report
        with open(master_report_path, "w") as f:
            f.write(content)

    def _compile_integrated_insights(self, all_runs_data: List[Dict]) -> Dict:
        """Compile insights from all runs into integrated analysis"""
        integrated = {
            "modes": {},
            "total_interviews": 0,
            "total_runs": len(all_runs_data),
            "solution_fit_analysis": {},
            "pain_points": [],
            "micro_features": [],
            "persona_demographics": [],
            "run_summary": [],
        }

        for run_data in all_runs_data:
            if "insights" in run_data:  # Current run
                insights = run_data["insights"]
                integrated["total_interviews"] += run_data["completed"]

                # Process current run insights
                for insight in insights:
                    mode = insight["mode"]
                    hypothesis = insight["hypothesis"]
                    insight_text = insight["insights"]

                    # Initialize mode/hypothesis tracking
                    if mode not in integrated["modes"]:
                        integrated["modes"][mode] = {}
                    if hypothesis not in integrated["modes"][mode]:
                        integrated["modes"][mode][hypothesis] = {
                            "solution_fits": [],
                            "pain_points": [],
                            "micro_features": [],
                            "persona_count": 0,
                        }

                    # Extract and categorize insights
                    integrated["modes"][mode][hypothesis]["persona_count"] += 1

                    # Solution fit analysis
                    if "Aligned? Yes" in insight_text:
                        integrated["modes"][mode][hypothesis]["solution_fits"].append(
                            "✅ Aligned"
                        )
                    elif "Aligned? No" in insight_text:
                        integrated["modes"][mode][hypothesis]["solution_fits"].append(
                            "❌ Misaligned"
                        )

                    # Pain points
                    if "Pain Points:" in insight_text:
                        pain_section = insight_text.split("Pain Points:")[1].split(
                            "Desired Outcomes:"
                        )[0]
                        pain_points = []
                        for line in pain_section.split("\n"):
                            line = line.strip()
                            if line.startswith("-") and line[1:].strip():
                                pain_points.append(line[1:].strip())
                        integrated["modes"][mode][hypothesis]["pain_points"].extend(
                            pain_points
                        )
                        integrated["pain_points"].extend(pain_points)

                    # Micro-features
                    if "Micro-feature Suggestions:" in insight_text:
                        features_section = insight_text.split(
                            "Micro-feature Suggestions:"
                        )[1]
                        features = []
                        for line in features_section.split("\n"):
                            line = line.strip()
                            if (
                                line
                                and not line.startswith("-")
                                and not line.startswith("##")
                            ):
                                features.append(line)
                        integrated["modes"][mode][hypothesis]["micro_features"].extend(
                            features
                        )
                        integrated["micro_features"].extend(features)

            # Add run summary
            integrated["run_summary"].append(
                {
                    "run_dir": run_data["run_dir"],
                    "interviews": run_data.get("completed", 0),
                    "failed": run_data.get("failed", 0),
                }
            )

        return integrated

    def _generate_comprehensive_master_report(
        self, integrated_insights: Dict, all_runs_data: List[Dict], project_name: str
    ) -> str:
        """Generate a comprehensive, well-structured master report"""
        content = f"""# Integrated Master Report - {project_name}

## Executive Summary

**Total Analysis:**
- **Runs Completed:** {integrated_insights['total_runs']}
- **Total Interviews:** {integrated_insights['total_interviews']}
- **Modes Analyzed:** {len(integrated_insights['modes'])}
- **Unique Pain Points Identified:** {len(set(integrated_insights['pain_points']))}
- **Micro-Features Suggested:** {len(set(integrated_insights['micro_features']))}

## Run History

"""

        # Add run history
        for run in integrated_insights["run_summary"]:
            content += f"- **{run['run_dir']}:** {run['interviews']} interviews, {run['failed']} failed\n"

        content += "\n## Comprehensive Insights by Mode\n\n"

        # Generate insights for each mode
        for mode, hypotheses in integrated_insights["modes"].items():
            content += f"### {mode} Mode\n\n"

            for hypothesis, data in hypotheses.items():
                content += f"#### {hypothesis}\n"

                # Solution fit analysis
                if data["solution_fits"]:
                    aligned_count = data["solution_fits"].count("✅ Aligned")
                    total_count = len(data["solution_fits"])
                    alignment_rate = (aligned_count / total_count) * 100
                    content += f"- **Solution Alignment:** {aligned_count}/{total_count} personas ({alignment_rate:.1f}%)\n"

                # Top pain points (deduplicated and ranked)
                if data["pain_points"]:
                    pain_point_counts = {}
                    for point in data["pain_points"]:
                        pain_point_counts[point] = pain_point_counts.get(point, 0) + 1
                    top_pain_points = sorted(
                        pain_point_counts.items(), key=lambda x: x[1], reverse=True
                    )[:5]
                    content += f"- **Top Pain Points:**\n"
                    for point, count in top_pain_points:
                        content += f"  - {point} (mentioned {count} times)\n"

                # Top micro-features (deduplicated and ranked)
                if data["micro_features"]:
                    feature_counts = {}
                    for feature in data["micro_features"]:
                        feature_counts[feature] = feature_counts.get(feature, 0) + 1
                    top_features = sorted(
                        feature_counts.items(), key=lambda x: x[1], reverse=True
                    )[:3]
                    content += f"- **Top Feature Suggestions:**\n"
                    for feature, count in top_features:
                        content += f"  - {feature} (suggested {count} times)\n"

                content += "\n"

        # Add cross-cutting themes
        content += "## Cross-Cutting Themes\n\n"

        # Most common pain points across all modes
        all_pain_points = integrated_insights["pain_points"]
        if all_pain_points:
            pain_point_counts = {}
            for point in all_pain_points:
                pain_point_counts[point] = pain_point_counts.get(point, 0) + 1
            top_global_pain_points = sorted(
                pain_point_counts.items(), key=lambda x: x[1], reverse=True
            )[:10]

            content += "### Most Common Pain Points\n"
            for point, count in top_global_pain_points:
                content += f"- {point} ({count} mentions)\n"
            content += "\n"

        # Most common micro-features across all modes
        all_features = integrated_insights["micro_features"]
        if all_features:
            feature_counts = {}
            for feature in all_features:
                feature_counts[feature] = feature_counts.get(feature, 0) + 1
            top_global_features = sorted(
                feature_counts.items(), key=lambda x: x[1], reverse=True
            )[:10]

            content += "### Most Requested Features\n"
            for feature, count in top_global_features:
                content += f"- {feature} ({count} suggestions)\n"
            content += "\n"

        return content

    def _update_integrated_roadmap(
        self,
        roadmap_path: Path,
        all_insights: List[Dict],
        run_metadata: Dict,
    ):
        """Generate or update the integrated development roadmap with intelligent prioritization"""
        # Load all existing run data from the project directory
        project_dir = roadmap_path.parent
        all_runs_data = []

        # Collect data from all run directories
        for run_dir in project_dir.glob("run_*"):
            run_master_path = run_dir / "master_report.md"
            if run_master_path.exists():
                with open(run_master_path, "r") as f:
                    run_content = f.read()
                    all_runs_data.append(
                        {"run_dir": run_dir.name, "content": run_content}
                    )

        # Add current run data
        current_run_data = {
            "run_dir": f"run_{run_metadata['run_timestamp']}",
            "insights": all_insights,
            "metadata": run_metadata,
        }
        all_runs_data.append(current_run_data)

        # Compile integrated roadmap data
        roadmap_data = self._compile_roadmap_data(all_runs_data)

        # Generate comprehensive roadmap
        content = self._generate_comprehensive_roadmap(roadmap_data, project_dir.name)

        # Write the integrated roadmap
        with open(roadmap_path, "w") as f:
            f.write(content)

    def _compile_roadmap_data(self, all_runs_data: List[Dict]) -> Dict:
        """Compile roadmap data from all runs"""
        roadmap_data = {
            "solution_fit_scores": {},
            "micro_features": [],
            "pain_points": [],
            "run_summary": [],
            "total_interviews": 0,
        }

        for run_data in all_runs_data:
            if "insights" in run_data:  # Current run
                insights = run_data["insights"]
                roadmap_data["total_interviews"] += run_data["metadata"][
                    "total_interviews"
                ]

                for insight in insights:
                    insight_text = insight["insights"]
                    mode = insight["mode"]
                    hypothesis = insight["hypothesis"]

                    # Track solution fit by mode/hypothesis
                    key = f"{mode}/{hypothesis}"
                    if key not in roadmap_data["solution_fit_scores"]:
                        roadmap_data["solution_fit_scores"][key] = {
                            "aligned": 0,
                            "total": 0,
                        }

                    if "Aligned? Yes" in insight_text:
                        roadmap_data["solution_fit_scores"][key]["aligned"] += 1
                    roadmap_data["solution_fit_scores"][key]["total"] += 1

                    # Extract micro-features
                    if "Micro-feature Suggestions:" in insight_text:
                        features_section = insight_text.split(
                            "Micro-feature Suggestions:"
                        )[1]
                        features = []
                        for line in features_section.split("\n"):
                            line = line.strip()
                            if (
                                line
                                and not line.startswith("-")
                                and not line.startswith("##")
                            ):
                                features.append(line)
                        roadmap_data["micro_features"].extend(features)

                    # Extract pain points
                    if "Pain Points:" in insight_text:
                        pain_section = insight_text.split("Pain Points:")[1].split(
                            "Desired Outcomes:"
                        )[0]
                        pain_points = []
                        for line in pain_section.split("\n"):
                            line = line.strip()
                            if line.startswith("-") and line[1:].strip():
                                pain_points.append(line[1:].strip())
                        roadmap_data["pain_points"].extend(pain_points)

            # Add run summary
            roadmap_data["run_summary"].append(
                {
                    "run_dir": run_data["run_dir"],
                    "interviews": run_data.get("metadata", {}).get(
                        "total_interviews", 0
                    ),
                }
            )

        return roadmap_data

    def _generate_comprehensive_roadmap(
        self, roadmap_data: Dict, project_name: str
    ) -> str:
        """Generate a comprehensive, prioritized development roadmap"""
        content = f"""# Integrated Development Roadmap - {project_name}

## Executive Summary

**Analysis Overview:**
- **Total Runs:** {len(roadmap_data['run_summary'])}
- **Total Interviews:** {roadmap_data['total_interviews']}
- **Features Analyzed:** {len(roadmap_data['solution_fit_scores'])}
- **Unique Micro-Features:** {len(set(roadmap_data['micro_features']))}
- **Pain Points Identified:** {len(set(roadmap_data['pain_points']))}

## Run History

"""

        # Add run history
        for run in roadmap_data["run_summary"]:
            content += f"- **{run['run_dir']}:** {run['interviews']} interviews\n"

        content += "\n## Prioritized Development Recommendations\n\n"

        # Categorize features by alignment strength
        high_priority = []
        medium_priority = []
        low_priority = []

        for key, scores in roadmap_data["solution_fit_scores"].items():
            if scores["total"] > 0:
                alignment_rate = scores["aligned"] / scores["total"]
                if alignment_rate >= 0.7:
                    high_priority.append((key, alignment_rate))
                elif alignment_rate >= 0.4:
                    medium_priority.append((key, alignment_rate))
                else:
                    low_priority.append((key, alignment_rate))

        # Sort by alignment rate
        high_priority.sort(key=lambda x: x[1], reverse=True)
        medium_priority.sort(key=lambda x: x[1], reverse=True)
        low_priority.sort(key=lambda x: x[1], reverse=True)

        # High Priority Features
        if high_priority:
            content += "### 🔥 High Priority (Strong User Alignment)\n\n"
            for feature, alignment_rate in high_priority:
                mode, hypothesis = feature.split("/")
                content += f"#### {hypothesis} ({mode} mode)\n"
                content += f"- **Alignment Rate:** {alignment_rate:.1%}\n"
                content += f"- **Justification:** Strong user alignment across diverse personas\n"
                content += f"- **Success Measures:** User engagement, retention, positive feedback\n"
                content += f"- **Timeline:** Next sprint\n"
                content += f"- **Implementation Priority:** Critical\n\n"

        # Medium Priority Features
        if medium_priority:
            content += "### ⚡ Medium Priority (Moderate User Alignment)\n\n"
            for feature, alignment_rate in medium_priority:
                mode, hypothesis = feature.split("/")
                content += f"#### {hypothesis} ({mode} mode)\n"
                content += f"- **Alignment Rate:** {alignment_rate:.1%}\n"
                content += (
                    f"- **Justification:** Moderate user alignment, needs refinement\n"
                )
                content += f"- **Success Measures:** User testing, iteration based on feedback\n"
                content += f"- **Timeline:** Next quarter\n"
                content += f"- **Implementation Priority:** Important\n\n"

        # Low Priority Features
        if low_priority:
            content += "### 📋 Low Priority (Weak User Alignment)\n\n"
            for feature, alignment_rate in low_priority:
                mode, hypothesis = feature.split("/")
                content += f"#### {hypothesis} ({mode} mode)\n"
                content += f"- **Alignment Rate:** {alignment_rate:.1%}\n"
                content += f"- **Justification:** Weak user alignment, needs significant rethinking\n"
                content += (
                    f"- **Success Measures:** User research, concept validation\n"
                )
                content += f"- **Timeline:** Future consideration\n"
                content += f"- **Implementation Priority:** Low\n\n"

        # Micro-Feature Analysis
        if roadmap_data["micro_features"]:
            feature_counts = {}
            for feature in roadmap_data["micro_features"]:
                feature_counts[feature] = feature_counts.get(feature, 0) + 1

            top_features = sorted(
                feature_counts.items(), key=lambda x: x[1], reverse=True
            )[:15]

            content += "## 🎯 Top Micro-Feature Suggestions\n\n"
            content += (
                "**Ranked by frequency of suggestion across all interviews:**\n\n"
            )

            for i, (feature, count) in enumerate(top_features, 1):
                content += f"{i}. **{feature}** ({count} suggestions)\n"
            content += "\n"

        # Pain Point Analysis
        if roadmap_data["pain_points"]:
            pain_point_counts = {}
            for point in roadmap_data["pain_points"]:
                pain_point_counts[point] = pain_point_counts.get(point, 0) + 1

            top_pain_points = sorted(
                pain_point_counts.items(), key=lambda x: x[1], reverse=True
            )[:10]

            content += "## 🚨 Critical Pain Points to Address\n\n"
            content += "**Ranked by frequency of mention across all interviews:**\n\n"

            for i, (point, count) in enumerate(top_pain_points, 1):
                content += f"{i}. **{point}** ({count} mentions)\n"
            content += "\n"

        # Implementation Strategy
        content += "## 📋 Implementation Strategy\n\n"

        if high_priority:
            content += "### Phase 1: High-Priority Features (Next Sprint)\n"
            for feature, _ in high_priority[:3]:  # Top 3
                mode, hypothesis = feature.split("/")
                content += f"- Implement {hypothesis} for {mode} mode\n"
            content += "\n"

        if medium_priority:
            content += "### Phase 2: Medium-Priority Features (Next Quarter)\n"
            for feature, _ in medium_priority[:3]:  # Top 3
                mode, hypothesis = feature.split("/")
                content += f"- Research and refine {hypothesis} for {mode} mode\n"
            content += "\n"

        content += "### Phase 3: Continuous Improvement\n"
        content += "- Monitor user feedback on implemented features\n"
        content += "- Iterate based on real-world usage data\n"
        content += "- Plan next round of user research\n"

        return content

    def _create_test_config(self) -> ProjectConfig:
        """Create a test configuration for testing purposes"""
        return ProjectConfig(
            project_name="TestProject",
            llm_model="gpt-4o-mini",
            product_sketch="An AI-powered emotional regulation coaching app",
            interview_modes=[
                InterviewMode(
                    mode="trauma_informed",
                    persona_count=3,
                    problem_hypotheses=[
                        ProblemHypothesis(
                            label="emotional_overwhelm",
                            description="Users experience intense emotional overwhelm",
                        )
                    ],
                )
            ],
            output_format="markdown",
        )

    def _generate_interview_prompt(
        self,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona_variant: int,
        run_timestamp: str,
    ) -> str:
        """Generate the interview prompt for a specific persona with run-specific randomization"""

        # Create a unique seed for this specific interview to ensure variety
        seed_string = (
            f"{run_timestamp}_{mode.mode}_{hypothesis.label}_{persona_variant}"
        )
        random.seed(hash(seed_string) % (2**32))  # Ensure seed is within valid range

        # Generate random elements to ensure unique personas each run
        random_elements = {
            "age_group": random.choice(
                [
                    "early 20s",
                    "late 20s",
                    "early 30s",
                    "late 30s",
                    "early 40s",
                    "late 40s",
                    "early 50s",
                ]
            ),
            "life_stage": random.choice(
                [
                    "student",
                    "early career",
                    "mid-career",
                    "career transition",
                    "established professional",
                    "returning to work",
                ]
            ),
            "emotional_baseline": random.choice(
                [
                    "anxious",
                    "depressed",
                    "overwhelmed",
                    "numb",
                    "frustrated",
                    "hopeful",
                    "determined",
                    "exhausted",
                ]
            ),
            "coping_style": random.choice(
                [
                    "avoidant",
                    "confrontational",
                    "support-seeking",
                    "self-reliant",
                    "distraction-based",
                    "reflective",
                ]
            ),
            "readiness_level": random.choice(
                ["resistant", "ambivalent", "curious", "ready", "desperate", "cautious"]
            ),
            "background_factor": random.choice(
                [
                    "trauma history",
                    "perfectionism",
                    "people-pleasing",
                    "imposter syndrome",
                    "burnout",
                    "caregiver stress",
                    "work-life imbalance",
                ]
            ),
            "unique_challenge": random.choice(
                [
                    "financial stress",
                    "relationship issues",
                    "health concerns",
                    "career uncertainty",
                    "identity crisis",
                    "social isolation",
                    "time management",
                ]
            ),
        }

        prompt = f"""[INTERNAL CONTEXT: Product sketch—do NOT share with persona]
"{config.product_sketch}"

=== ASSIGNMENT ===
Project: {config.project_name}
Interview Mode: {mode.mode}
Problem Hypothesis: {hypothesis.label}
Hypothesis Description: {hypothesis.description}
Persona Variant: {persona_variant} (one of {mode.persona_count} contrasting personas for this hypothesis)

=== RANDOMIZATION CONTEXT ===
To ensure unique persona generation, incorporate these elements naturally:
- Age Group: {random_elements['age_group']}
- Life Stage: {random_elements['life_stage']}
- Emotional Baseline: {random_elements['emotional_baseline']}
- Coping Style: {random_elements['coping_style']}
- Readiness Level: {random_elements['readiness_level']}
- Background Factor: {random_elements['background_factor']}
- Unique Challenge: {random_elements['unique_challenge']}

=== PHASE 1: Persona Construction ===
Generate a fully fleshed, believable user persona that contrasts with the other variants along at least two meaningful axes (e.g., age/life stage, emotional baseline, coping strategy, readiness/resistance, internal conflict). Incorporate the randomization elements naturally into the persona. Include:
- Placeholder name
- Demographics and context
- Emotional baseline and variability
- Internal conflicts or resistance tied to the hypothesis
- Existing coping behaviors or avoidance patterns
- Implicit goals and success definitions

=== PHASE 2: Interview Simulation ===
Conduct a semi-structured, emotionally intelligent interview of 7–10 questions, roleplaying two voices:
1. Interviewer: trauma-aware / mode-appropriate tone. Ask open-ended, exploratory questions about the persona's lived experience relevant to the hypothesis. Do NOT mention, pitch, validate, or justify the internal solution sketch.
2. Persona: respond with human-like nuance (hesitations, contradictions, emotional texture, subtext, partial truths, hopes, and concerns).

Focus on:
- Current experience with the problem
- Emotional triggers and friction
- Desired outcomes and what "success" feels like
- Language the persona uses (self-talk and external)
- Behavioral / emotional readiness or distress signals

Format the dialogue as a transcript with clear speaker labels.

=== PHASE 3: Insight Synthesis ===
Produce a structured insight summary including:
- Pain Points
- Desired Outcomes
- Language Patterns
- Success Signals
- Emotional Triggers / Friction
- Recommended Tone (how to speak to this persona)
- Personality / Cognitive Tendencies
- Solution Fit Assessment:
    * Aligned? (yes/no)
    * If aligned: why.
    * If misaligned: what would better serve this persona.
- Up to 3 organically emerging micro-feature suggestions.

Output all of the above in the specified {config.output_format} with explicit sections:
## Persona
## Interview Transcript
## Insight Summary"""

        return prompt

    def _update_design_log(
        self,
        config: ProjectConfig,
        run_metadata: Dict = None,
        all_insights: List[Dict] = None,
    ):
        """Update the design log with a summary of the current run and its insights."""
        # Create version-aware design log path
        if self.config_dir:
            # Version-aware mode: create design log in config directory
            log_path = self.config_path / "design_log.md"
        else:
            # Legacy mode: create in project output directory
            log_path = Path("outputs") / config.project_name / "design_log.md"
            log_path.parent.mkdir(exist_ok=True)

        timestamp = datetime.now().strftime("%Y-%m-%d %H:%M:%S")

        # Read existing design log if it exists
        existing_content = ""
        if log_path.exists():
            with open(log_path, "r") as f:
                existing_content = f.read()

        # Create new entry
        new_entry = f"""# Design Log - {config.project_name}

## Run: {timestamp}

**Configuration:**
- **Version:** {config.version}
- **Model:** {config.llm_model}
- **Output Format:** {config.output_format}
- **Interview Modes:** {len(config.interview_modes)}
- **Total Interviews:** {sum(mode.persona_count * len(mode.problem_hypotheses) for mode in config.interview_modes)}

**Modes & Persona Counts Executed:**
"""

        for mode in config.interview_modes:
            new_entry += f"- **{mode.mode}:** {mode.persona_count} personas, {len(mode.problem_hypotheses)} hypotheses\n"

        new_entry += "\n**Hypotheses Tested:**\n"
        for mode in config.interview_modes:
            for hypothesis in mode.problem_hypotheses:
                new_entry += (
                    f"- **{hypothesis.label}:** {hypothesis.description[:100]}...\n"
                )

        if all_insights:
            new_entry += "\n**Key Insights from this Run:**\n"

            # Group insights by mode
            mode_insights = {}
            for insight in all_insights:
                mode = insight.get("mode", "Unknown")
                if mode not in mode_insights:
                    mode_insights[mode] = []
                mode_insights[mode].append(insight)

            for mode, insights in mode_insights.items():
                new_entry += f"\n### {mode} Mode\n"

                # Group by hypothesis
                hypothesis_insights = {}
                for insight in insights:
                    hypothesis = insight.get("hypothesis", "Unknown")
                    if hypothesis not in hypothesis_insights:
                        hypothesis_insights[hypothesis] = []
                    hypothesis_insights[hypothesis].append(insight)

                for hypothesis, hypothesis_insights_list in hypothesis_insights.items():
                    new_entry += f"\n#### {hypothesis}\n"

                    # Extract common themes
                    solution_fits = []
                    pain_points = []
                    micro_features = []

                    for insight in hypothesis_insights_list:
                        insight_text = insight.get("insights", "")

                        # Extract solution fit
                        if "Aligned? Yes" in insight_text:
                            solution_fits.append("✅ Aligned")
                        elif "Aligned? No" in insight_text:
                            solution_fits.append("❌ Misaligned")

                        # Extract pain points
                        if "Pain Points:" in insight_text:
                            try:
                                pain_section = insight_text.split("Pain Points:")[
                                    1
                                ].split("Desired Outcomes:")[0]
                                pain_points.extend(
                                    [
                                        p.strip()
                                        for p in pain_section.split("-")
                                        if p.strip()
                                    ]
                                )
                            except IndexError:
                                pass

                        # Extract micro-features
                        if "Micro-feature Suggestions:" in insight_text:
                            try:
                                features_section = insight_text.split(
                                    "Micro-feature Suggestions:"
                                )[1]
                                micro_features.extend(
                                    [
                                        f.strip()
                                        for f in features_section.split("\n")
                                        if f.strip() and not f.startswith("-")
                                    ]
                                )
                            except IndexError:
                                pass

                    # Add summary
                    if solution_fits:
                        aligned_count = solution_fits.count("✅ Aligned")
                        total_count = len(solution_fits)
                        new_entry += f"- **Solution Fit:** {aligned_count}/{total_count} personas aligned\n"

                    if pain_points:
                        unique_pain_points = list(set(pain_points))[
                            :3
                        ]  # Top 3 unique pain points
                        new_entry += (
                            f"- **Key Pain Points:** {', '.join(unique_pain_points)}\n"
                        )

                    if micro_features:
                        unique_features = list(set(micro_features))[
                            :3
                        ]  # Top 3 unique features
                        new_entry += (
                            f"- **Suggested Features:** {', '.join(unique_features)}\n"
                        )

        new_entry += "\n**Product Sketch Critique:**\n"
        new_entry += f"- Current sketch: {config.product_sketch[:200]}...\n"
        new_entry += "- [Add critique based on insights]\n"

        new_entry += "\n**Recommendations for Next Version:**\n"
        new_entry += "- [Add recommendations based on insights]\n"

        new_entry += "\n---\n\n"

        # Append to existing content
        updated_content = new_entry + existing_content

        with open(log_path, "w") as f:
            f.write(updated_content)

        print(f"✅ Design log updated: {log_path}")

    def _add_resonance_analysis_to_master_report(
        self, master_report_path: Path, config: ProjectConfig, all_insights: List[Dict]
    ):
        """Add Product Resonance Analysis section to master report."""
        if not master_report_path.exists():
            return

        with open(master_report_path, "r") as f:
            content = f.read()

        # Create resonance analysis section
        resonance_section = f"""
## Product Resonance Analysis

**Version:** {config.version}
**Analysis Date:** {datetime.now().strftime("%Y-%m-%d %H:%M:%S")}

### Current Version Assessment

**Product Sketch Resonance:**
- **Tone Alignment:** [Analyze how well the product tone landed with personas]
- **Hypothesis Validation:** [Which hypotheses resonated most/least]
- **Feature Direction:** [What feature directions need adjustment]

### Resonance Metrics

"""

        if all_insights:
            # Calculate alignment rates
            total_interviews = len(all_insights)
            aligned_count = 0

            for insight in all_insights:
                insight_text = insight.get("insights", "")
                if "Aligned? Yes" in insight_text:
                    aligned_count += 1

            alignment_rate = (
                (aligned_count / total_interviews * 100) if total_interviews > 0 else 0
            )
            resonance_section += f"- **Overall Alignment Rate:** {alignment_rate:.1f}% ({aligned_count}/{total_interviews})\n"

            # Group by mode for detailed analysis
            mode_alignment = {}
            for insight in all_insights:
                mode = insight.get("mode", "Unknown")
                if mode not in mode_alignment:
                    mode_alignment[mode] = {"total": 0, "aligned": 0}

                mode_alignment[mode]["total"] += 1
                if "Aligned? Yes" in insight.get("insights", ""):
                    mode_alignment[mode]["aligned"] += 1

            resonance_section += "\n**Mode-Specific Resonance:**\n"
            for mode, stats in mode_alignment.items():
                rate = (
                    (stats["aligned"] / stats["total"] * 100)
                    if stats["total"] > 0
                    else 0
                )
                resonance_section += (
                    f"- **{mode}:** {rate:.1f}% ({stats['aligned']}/{stats['total']})\n"
                )

        resonance_section += """
### Recommendations for Next Version

**Tone Adjustments:**
- [Specific tone changes based on resonance analysis]

**Hypothesis Refinements:**
- [Which hypotheses to keep, modify, or discard]

**Feature Direction Changes:**
- [Specific feature adjustments based on user feedback]

**Risk Mitigation:**
- [Address any misalignment issues identified]
"""

        # Insert resonance section after the first heading
        if "## " in content:
            parts = content.split("## ", 1)
            updated_content = (
                parts[0]
                + "## "
                + parts[1].replace("## ", resonance_section + "\n## ", 1)
            )
        else:
            updated_content = content + resonance_section

        with open(master_report_path, "w") as f:
            f.write(updated_content)

        print(f"✅ Resonance analysis added to master report")


class InsightExtractor:
    """
    Utility class for extracting insights from interview responses.
    Centralizes all insight extraction logic to eliminate duplication.
    """

    # Alignment indicators for detecting if hypotheses are aligned
    ALIGNMENT_INDICATORS = [
        "aligned? yes",
        "aligned: yes",
        "alignment: yes",
        "aligned yes",
        "yes - this persona's needs align",
        "yes - this persona's needs align with our hypothesis",
        "aligned with our hypothesis",
        "needs align with our hypothesis",
    ]

    @classmethod
    def extract_alignment(cls, insight_text: str) -> bool:
        """Extract alignment status from insight text."""
        insight_text_lower = insight_text.lower()
        return any(
            indicator in insight_text_lower for indicator in cls.ALIGNMENT_INDICATORS
        )

    @classmethod
    def extract_pain_points(cls, insight_text: str) -> List[str]:
        """Extract pain points from insight text."""
        pain_points = []

        if "## Pain Points" in insight_text:
            try:
                start = insight_text.find("## Pain Points")
                end = insight_text.find("##", start + 1)
                if end == -1:
                    end = len(insight_text)
                pain_section = insight_text[start:end]

                # Extract lines starting with "-"
                lines = pain_section.split("\n")
                for line in lines:
                    line = line.strip()
                    if line.startswith("-"):
                        point = line[1:].strip()  # Remove the dash
                        if point:
                            pain_points.append(point)
            except IndexError:
                pass

        return pain_points

    @classmethod
    def extract_desired_outcomes(cls, insight_text: str) -> List[str]:
        """Extract desired outcomes from insight text."""
        outcomes = []

        if "## Desired Outcomes" in insight_text:
            try:
                start = insight_text.find("## Desired Outcomes")
                end = insight_text.find("##", start + 1)
                if end == -1:
                    end = len(insight_text)
                outcomes_section = insight_text[start:end]

                # Extract lines starting with "-"
                lines = outcomes_section.split("\n")
                for line in lines:
                    line = line.strip()
                    if line.startswith("-"):
                        outcome = line[1:].strip()  # Remove the dash
                        if outcome:
                            outcomes.append(outcome)
            except IndexError:
                pass

        return outcomes

    @classmethod
    def process_insight(cls, insight: Dict) -> Dict:
        """Process a single insight and extract all relevant information."""
        insight_text = insight.get("insights", "")

        return {
            "mode": insight.get("mode", "Unknown"),
            "hypothesis": insight.get("hypothesis", "Unknown"),
            "aligned": cls.extract_alignment(insight_text),
            "pain_points": cls.extract_pain_points(insight_text),
            "desired_outcomes": cls.extract_desired_outcomes(insight_text),
            "micro_features": [],  # Placeholder for future implementation
        }


class PromptGenerator:
    """
    Utility class for generating interview prompts.
    Centralizes prompt generation logic to eliminate duplication.
    """

    # Random elements for persona generation
    RANDOM_ELEMENTS = {
        "age_group": [
            "early 20s",
            "late 20s",
            "early 30s",
            "late 30s",
            "early 40s",
            "late 40s",
            "early 50s",
        ],
        "life_stage": [
            "student",
            "early career",
            "mid-career",
            "career transition",
            "established professional",
            "returning to work",
        ],
        "emotional_baseline": [
            "anxious",
            "depressed",
            "overwhelmed",
            "numb",
            "frustrated",
            "hopeful",
            "determined",
            "exhausted",
        ],
        "coping_style": [
            "avoidant",
            "confrontational",
            "support-seeking",
            "self-reliant",
            "distraction-based",
            "reflective",
        ],
        "readiness_level": [
            "resistant",
            "ambivalent",
            "curious",
            "ready",
            "desperate",
            "cautious",
        ],
        "background_factor": [
            "trauma history",
            "perfectionism",
            "people-pleasing",
            "imposter syndrome",
            "burnout",
            "caregiver stress",
            "work-life imbalance",
        ],
        "unique_challenge": [
            "financial stress",
            "relationship issues",
            "health concerns",
            "career uncertainty",
            "identity crisis",
            "social isolation",
            "time management",
        ],
    }

    @classmethod
    def generate_random_elements(cls, seed_string: str) -> Dict[str, str]:
        """Generate random elements for persona creation based on seed."""
        random.seed(hash(seed_string) % (2**32))  # Ensure seed is within valid range

        return {
            key: random.choice(values) for key, values in cls.RANDOM_ELEMENTS.items()
        }

    @classmethod
    def generate_interview_prompt(
        cls,
        config: ProjectConfig,
        mode: InterviewMode,
        hypothesis: ProblemHypothesis,
        persona_variant: int,
        run_timestamp: str,
        persona: Dict = None,
    ) -> str:
        """Generate interview prompt with consistent structure."""
        # Create a unique seed for this specific interview
        seed_string = (
            f"{run_timestamp}_{mode.mode}_{hypothesis.label}_{persona_variant}"
        )
        random_elements = cls.generate_random_elements(seed_string)

        # Build the prompt
        return PromptGenerator.generate_interview_prompt(
            config, mode, hypothesis, persona_variant, run_timestamp
        )


class ConfigManager:
    """
    Utility class for managing configuration loading and saving.
    Centralizes config management logic to eliminate duplication.
    """

    @staticmethod
    def load_config_from_json(config_path: str) -> ProjectConfig:
        """Load configuration from JSON file."""
        with open(config_path, "r") as f:
            data = json.load(f)

        # Convert interview modes
        interview_modes = []
        for mode_data in data.get("interview_modes", []):
            mode = InterviewMode(
                mode=mode_data["mode"],
                persona_count=mode_data["persona_count"],
                problem_hypotheses=[],
            )

            for hyp_data in mode_data.get("problem_hypotheses", []):
                hypothesis = ProblemHypothesis(
                    label=hyp_data["label"], description=hyp_data["description"]
                )
                mode.problem_hypotheses.append(hypothesis)

            interview_modes.append(mode)

        return ProjectConfig(
            project_name=data["project_name"],
            llm_model=data.get("llm_model", "gpt-4o-mini"),
            product_sketch=data.get("product_sketch", ""),
            interview_modes=interview_modes,
            output_format=data.get("output_format", "markdown"),
            version=data.get("version", "v1"),
        )

    @staticmethod
    def config_to_dict(config: ProjectConfig) -> Dict:
        """Convert ProjectConfig to dictionary."""
        return {
            "project_name": config.project_name,
            "llm_model": config.llm_model,
            "product_sketch": config.product_sketch,
            "output_format": config.output_format,
            "version": config.version,
            "interview_modes": [
                {
                    "mode": mode.mode,
                    "persona_count": mode.persona_count,
                    "problem_hypotheses": [
                        {"label": hyp.label, "description": hyp.description}
                        for hyp in mode.problem_hypotheses
                    ],
                }
                for mode in config.interview_modes
            ],
        }

    @staticmethod
    def save_config_to_json(config: ProjectConfig, config_path: str):
        """Save configuration to JSON file."""
        config_dict = ConfigManager.config_to_dict(config)
        with open(config_path, "w") as f:
            json.dump(config_dict, f, indent=2)


class LLMRoadmapGenerator:
    """
    LLM-driven roadmap generator that creates intelligent, prioritized roadmaps
    based on user insights rather than simple frequency counting.
    """

    def __init__(self, api_key: Optional[str] = None):
        """Initialize the LLM roadmap generator."""
        self.api_key = api_key or os.getenv("OPENAI_API_KEY")
        if not self.api_key:
            raise ValueError("OpenAI API key is required")

        openai.api_key = self.api_key

    async def generate_prioritized_roadmap_async(
        self, insights: List[Dict], project_name: str
    ) -> str:
        """Generate a prioritized roadmap using LLM for intelligent analysis."""
        if not insights:
            return self._generate_empty_roadmap(project_name)

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Create an intelligent, prioritized product roadmap for "{project_name}" based on these user insights:

{insights_summary}

Generate a roadmap that:
1. Prioritizes features based on user needs, not just frequency
2. Considers the severity and impact of pain points
3. Evaluates the feasibility and value of desired outcomes
4. Provides clear, actionable next steps
5. Includes timeline recommendations
6. Explains the reasoning behind prioritization

Write in conversational English that makes the roadmap maximally usable for product teams."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating roadmap: {str(e)}"

    async def synthesize_features_from_insights_async(
        self, insights: List[Dict]
    ) -> Dict:
        """Synthesize features from insights using LLM."""
        if not insights:
            return {"features": [], "reasoning": "No insights available"}

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Based on these user insights, synthesize potential product features:

{insights_summary}

Provide a JSON response with:
{{
    "features": ["list", "of", "synthesized", "features"],
    "reasoning": "explanation of how features address user needs",
    "priority": {{"feature": "high/medium/low"}},
    "user_value": {{"feature": "explanation of user value"}}
}}

Focus on features that directly address the pain points and desired outcomes identified."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return json.loads(response)

        except Exception as e:
            return {
                "features": [],
                "reasoning": f"Error synthesizing features: {str(e)}",
            }

    async def prioritize_pain_points_intelligently_async(
        self, insights: List[Dict]
    ) -> Dict:
        """Prioritize pain points intelligently using LLM."""
        if not insights:
            return {"high_priority": [], "reasoning": "No insights available"}

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Analyze these insights and prioritize pain points intelligently:

{insights_summary}

Provide a JSON response with:
{{
    "high_priority": ["list", "of", "high", "priority", "pain", "points"],
    "medium_priority": ["list", "of", "medium", "priority", "pain", "points"],
    "low_priority": ["list", "of", "low", "priority", "pain", "points"],
    "reasoning": "explanation of prioritization logic",
    "impact_analysis": "analysis of business and user impact"
}}

Consider severity, frequency, and business impact in your prioritization."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return json.loads(response)

        except Exception as e:
            return {
                "high_priority": [],
                "reasoning": f"Error prioritizing pain points: {str(e)}",
            }

    async def generate_actionable_roadmap_async(self, insights: List[Dict]) -> str:
        """Generate actionable roadmap with clear next steps."""
        if not insights:
            return "No insights available for roadmap generation."

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Create an actionable product roadmap based on these insights:

{insights_summary}

The roadmap should include:
1. Immediate Actions (next 2 weeks)
2. Short-term Goals (next month)
3. Medium-term Objectives (next quarter)
4. Long-term Vision (next 6 months)
5. Success Metrics
6. Risk Mitigation

Write in clear, actionable language that product teams can immediately use."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating actionable roadmap: {str(e)}"

    async def consider_business_context_async(
        self, insights: List[Dict], business_context: str
    ) -> str:
        """Generate roadmap considering business context."""
        if not insights:
            return "No insights available for roadmap generation."

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Create a product roadmap that considers both user insights and business context:

USER INSIGHTS:
{insights_summary}

BUSINESS CONTEXT:
{business_context}

Generate a roadmap that:
1. Balances user needs with business constraints
2. Prioritizes features based on both user value and business feasibility
3. Considers resource limitations and technical constraints
4. Provides realistic timelines and milestones
5. Includes risk assessment and mitigation strategies

Write in practical, business-aware language."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating business-aware roadmap: {str(e)}"

    async def handle_conflicting_insights_async(self, insights: List[Dict]) -> str:
        """Handle conflicting insights intelligently."""
        if not insights:
            return "No insights available for analysis."

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Analyze these potentially conflicting insights and provide resolution:

{insights_summary}

Provide a roadmap that:
1. Identifies and explains conflicts
2. Suggests approaches to resolve conflicts
3. Prioritizes based on user impact and business value
4. Provides clear decision-making criteria
5. Includes A/B testing or research recommendations where appropriate

Write in a balanced, analytical tone that helps teams make informed decisions."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error handling conflicting insights: {str(e)}"

    def _prepare_insights_summary(self, insights: List[Dict]) -> str:
        """Prepare insights for LLM processing."""
        summary_parts = []

        for i, insight in enumerate(insights, 1):
            summary_parts.append(f"Insight {i}:")
            summary_parts.append(f"- Aligned: {insight.get('aligned', 'Unknown')}")
            summary_parts.append(
                f"- Pain Points: {', '.join(insight.get('pain_points', []))}"
            )
            summary_parts.append(
                f"- Desired Outcomes: {', '.join(insight.get('desired_outcomes', []))}"
            )
            if insight.get("summary"):
                summary_parts.append(f"- Summary: {insight['summary']}")
            summary_parts.append("")

        return "\n".join(summary_parts)

    def _generate_empty_roadmap(self, project_name: str) -> str:
        """Generate a roadmap for when no insights are available."""
        return f"""# Product Roadmap - {project_name}

**Generated:** {datetime.now().strftime('%Y-%m-%d %H:%M:%S')}

## No Insights Available

This roadmap was generated without any user insights. Please run interviews to collect data for roadmap generation.

## Next Steps

1. Configure interview parameters
2. Run interview cycles
3. Collect and analyze insights
4. Generate prioritized roadmap"""

    async def _call_openai_async(self, prompt: str, model: str) -> str:
        """Call OpenAI API asynchronously."""
        try:
            response = openai.chat.completions.create(
                model=model,
                messages=[
                    {
                        "role": "system",
                        "content": "You are an expert product strategist and roadmap planner. Create intelligent, actionable roadmaps that balance user needs with business realities.",
                    },
                    {"role": "user", "content": prompt},
                ],
                max_tokens=4000,
                temperature=0.3,
            )
            return response.choices[0].message.content
        except Exception as e:
            raise Exception(f"OpenAI API call failed: {str(e)}")


class LLMProductEvolution:
    """
    LLM-driven product evolution that uses actual LLM calls to evolve
    product sketches and generate new hypotheses based on user insights.
    """

    def __init__(self, api_key: Optional[str] = None):
        """Initialize the LLM product evolution engine."""
        self.api_key = api_key or os.getenv("OPENAI_API_KEY")
        if not self.api_key:
            raise ValueError("OpenAI API key is required")

        openai.api_key = self.api_key

    async def evolve_product_sketch_async(
        self, current_sketch: str, insights: List[Dict]
    ) -> str:
        """Evolve product sketch using LLM based on user insights."""
        if not insights:
            return current_sketch

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Evolve this product sketch based on user insights:

CURRENT PRODUCT SKETCH:
{current_sketch}

USER INSIGHTS:
{insights_summary}

Please evolve the product sketch to better address the user needs identified. Consider:
1. How to address the pain points mentioned
2. How to deliver the desired outcomes
3. Maintaining the core value proposition
4. Making the approach more specific and targeted
5. Adding new features or capabilities that would help users

Return the evolved product sketch in clear, actionable language."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"{current_sketch}\n\nError evolving product sketch: {str(e)}"

    async def generate_new_hypotheses_async(self, insights: List[Dict]) -> List[Dict]:
        """Generate new hypotheses using LLM based on insights."""
        if not insights:
            return []

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Based on these user insights, generate new problem hypotheses to test:

{insights_summary}

Generate 3-5 new hypotheses that:
1. Address the pain points identified
2. Leverage the desired outcomes mentioned
3. Are specific and testable
4. Build on the insights gathered

Provide a JSON response with:
{{
    "hypotheses": [
        {{
            "label": "short_hypothesis_name",
            "description": "detailed description of the hypothesis to test"
        }}
    ],
    "reasoning": "explanation of why these hypotheses are worth testing"
}}"""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            result = json.loads(response)
            return result.get("hypotheses", [])

        except Exception as e:
            return [
                {
                    "label": "error",
                    "description": f"Error generating hypotheses: {str(e)}",
                }
            ]

    async def analyze_evolution_signals_async(self, insights: List[Dict]) -> Dict:
        """Analyze evolution signals using LLM."""
        if not insights:
            return {"alignment_rate": 0.0, "evolution_priorities": []}

        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Analyze these insights and identify evolution signals:

{insights_summary}

Provide a JSON response with:
{{
    "alignment_rate": 0.0-1.0,
    "misaligned_hypotheses": ["list", "of", "misaligned", "hypotheses"],
    "aligned_hypotheses": ["list", "of", "aligned", "hypotheses"],
    "common_pain_points": ["list", "of", "common", "pain", "points"],
    "evolution_priorities": ["list", "of", "evolution", "priorities"],
    "success_patterns": ["list", "of", "success", "patterns"],
    "recommendations": ["list", "of", "evolution", "recommendations"]
}}"""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return json.loads(response)

        except Exception as e:
            return {
                "alignment_rate": 0.0,
                "evolution_priorities": [f"Error analyzing signals: {str(e)}"],
            }

    async def maintain_product_consistency_async(
        self, original_sketch: str, evolved_sketch: str
    ) -> Dict:
        """Check if evolved product maintains consistency with original."""
        try:
            prompt = f"""Analyze if this evolved product sketch maintains consistency with the original:

ORIGINAL SKETCH:
{original_sketch}

EVOLVED SKETCH:
{evolved_sketch}

Provide a JSON response with:
{{
    "is_consistent": true/false,
    "reasoning": "explanation of consistency assessment",
    "improvements": ["list", "of", "improvements", "made"],
    "risks": ["list", "of", "potential", "risks"],
    "recommendations": ["list", "of", "consistency", "recommendations"]
}}"""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return json.loads(response)

        except Exception as e:
            return {
                "is_consistent": False,
                "reasoning": f"Error checking consistency: {str(e)}",
            }

    async def validate_evolution_quality_async(
        self, original_sketch: str, evolved_sketch: str
    ) -> Dict:
        """Validate the quality of evolution using LLM."""
        try:
            prompt = f"""Evaluate the quality of this product evolution:

ORIGINAL SKETCH:
{original_sketch}

EVOLVED SKETCH:
{evolved_sketch}

Provide a JSON response with:
{{
    "score": 0.0-1.0,
    "reasoning": "detailed explanation of quality assessment",
    "strengths": ["list", "of", "evolution", "strengths"],
    "weaknesses": ["list", "of", "evolution", "weaknesses"],
    "suggestions": ["list", "of", "improvement", "suggestions"]
}}"""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return json.loads(response)

        except Exception as e:
            return {"score": 0.0, "reasoning": f"Error validating evolution: {str(e)}"}

    async def generate_evolution_explanation_async(
        self, original_sketch: str, evolved_sketch: str, insights: List[Dict]
    ) -> str:
        """Generate explanation of evolution using LLM."""
        try:
            insights_summary = self._prepare_insights_summary(insights)

            prompt = f"""Explain how this product evolved based on user insights:

ORIGINAL SKETCH:
{original_sketch}

EVOLVED SKETCH:
{evolved_sketch}

USER INSIGHTS THAT DROVE EVOLUTION:
{insights_summary}

Write a clear, conversational explanation of:
1. What changed and why
2. How the evolution addresses user needs
3. The reasoning behind the changes
4. Expected impact on user experience

Write in a tone that helps stakeholders understand the evolution."""

            response = await self._call_openai_async(prompt, "gpt-4o-mini")
            return response

        except Exception as e:
            return f"Error generating evolution explanation: {str(e)}"

    def _prepare_insights_summary(self, insights: List[Dict]) -> str:
        """Prepare insights for LLM processing."""
        summary_parts = []

        for i, insight in enumerate(insights, 1):
            summary_parts.append(f"Insight {i}:")
            summary_parts.append(f"- Aligned: {insight.get('aligned', 'Unknown')}")
            summary_parts.append(
                f"- Pain Points: {', '.join(insight.get('pain_points', []))}"
            )
            summary_parts.append(
                f"- Desired Outcomes: {', '.join(insight.get('desired_outcomes', []))}"
            )
            if insight.get("summary"):
                summary_parts.append(f"- Summary: {insight['summary']}")
            summary_parts.append("")

        return "\n".join(summary_parts)

    async def _call_openai_async(self, prompt: str, model: str) -> str:
        """Call OpenAI API asynchronously."""
        try:
            response = openai.chat.completions.create(
                model=model,
                messages=[
                    {
                        "role": "system",
                        "content": "You are an expert product strategist and evolution specialist. Help evolve products based on user insights while maintaining core value propositions.",
                    },
                    {"role": "user", "content": prompt},
                ],
                max_tokens=3000,
                temperature=0.4,
            )
            return response.choices[0].message.content
        except Exception as e:
            raise Exception(f"OpenAI API call failed: {str(e)}")


def main():
    """Main entry point"""
    # Load environment variables from .env file
    from dotenv import load_dotenv

    load_dotenv()

    try:
        parser = argparse.ArgumentParser(
            description="LLM Interview Engine - Run LLM-to-LLM research interviews."
        )
        parser.add_argument(
            "--api-key", type=str, help="OpenAI API key (optional, overrides .env)"
        )
        parser.add_argument(
            "--config-dir",
            type=str,
            help="Directory containing versioned configs (e.g., config/v2/)",
        )
        parser.add_argument(
            "--cycles", type=int, default=3, help="Number of iteration cycles to run"
        )
        parser.add_argument(
            "--evolution-enabled",
            action="store_true",
            help="Enable automatic product evolution",
        )
        args = parser.parse_args()

        # Check if we should run iterative research mode
        if args.config_dir and (args.cycles > 1 or args.evolution_enabled):
            print("🚀 Starting Async Iterative Research Mode")
            engine = AsyncIterativeResearchEngine(
                api_key=args.api_key,
                config_dir=args.config_dir,
                cycles=args.cycles,
                evolution_enabled=args.evolution_enabled,
            )
            results = asyncio.run(engine.run_iterative_research_async())
            print(f"\n✅ Async iterative research completed with {len(results)} cycles")
        else:
            # Initialize the standard engine
            engine = LLMInterviewEngine(
                api_key=args.api_key, config_dir=args.config_dir
            )
            # Run the CLI
            engine.run_cli()
    except KeyboardInterrupt:
        print("\n\n👋 Interview run cancelled by user.")
    except Exception as e:
        logger.error(f"Error: {e}")
        sys.exit(1)


if __name__ == "__main__":
    main()
