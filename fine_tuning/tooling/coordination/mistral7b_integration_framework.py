#!/usr/bin/env python3
"""
Mistral7b Integration Framework - LLM as Judge and Content Preparation
Leverages Mistral7b for evaluation, staging, and heavy computational tasks
"""

import ollama
import json
import asyncio
from pathlib import Path
from datetime import datetime
from typing import Dict, Any, List, Optional
import logging

class Mistral7bJudgeFramework:
    """Comprehensive framework for using Mistral7b as evaluation and preparation engine"""
    
    def __init__(self, workspace_root="/home/cgbowen/AIWorkspace"):
        self.workspace_root = Path(workspace_root)
        self.fine_tuning_dir = self.workspace_root / "fine_tuning"
        
        # Setup logging
        logging.basicConfig(level=logging.INFO)
        self.logger = logging.getLogger(__name__)
        
        # Evaluation rubrics for different educational contexts
        self.rubrics = {
            "tutoring": "Score 1-5. Is the explanation clear, accurate, and appropriate for the target audience? A 5 is exceptionally clear and helpful.",
            "humor": "Score 1-5. Is the response genuinely witty, clever, or funny? A 5 is a very good joke or punchline.",
            "persona_stoic": "Score 1-5. Does the response accurately reflect the principles of Stoic philosophy? A 5 is a wise and authentic response.",
            "family_tutor": "Score 1-5. Is the response warm, patient, and age-appropriate for family learning? A 5 shows excellent pedagogical approach.",
            "educational_expert": "Score 1-5. Does the response demonstrate deep subject knowledge with clear, structured explanations? A 5 is masterful teaching.",
            "philosophical_guide": "Score 1-5. Does the response encourage thoughtful reflection and critical thinking? A 5 inspires deep contemplation.",
            "methodology_effectiveness": "Score 1-5. How well does this demonstrate proven educational methodology? A 5 shows perfect pedagogical technique.",
            "step_by_step_clarity": "Score 1-5. Are the problem-solving steps clear, logical, and easy to follow? A 5 is perfectly structured reasoning.",
            "socratic_questioning": "Score 1-5. How effectively does this use questions to guide learning? A 5 demonstrates masterful Socratic technique.",
            "error_analysis": "Score 1-5. How well does this help identify and learn from mistakes? A 5 provides excellent error guidance.",
            "conceptual_explanation": "Score 1-5. How well does this connect to underlying concepts? A 5 provides deep conceptual understanding."
        }
    
    def llm_as_judge(self, prompt: str, response: str, category: str) -> Dict[str, Any]:
        """Uses local Mistral 7B model via Ollama to evaluate a response."""
        
        # Enhanced judge prompt for educational contexts
        judge_prompt = f"""You are an expert AI evaluator specializing in educational content assessment. Your task is to grade a tutoring model's response based on the provided rubric.
        
        Provide your evaluation ONLY as a JSON object with these keys:
        - "score" (integer from 1 to 5)
        - "rationale" (brief 1-2 sentence explanation)
        - "strengths" (what worked well)
        - "improvements" (specific suggestions for enhancement)
        
        Category: {category}
        Rubric: {self.rubrics.get(category, "Score 1-5 on general helpfulness.")}
        ---
        Original Prompt:
        {prompt}
        ---
        Model's Response:
        {response}
        ---
        Your JSON evaluation:
        """
        
        try:
            completion = ollama.chat(
                model="mistral:7b",  # Use your Mistral 7B model
                messages=[{'role': 'user', 'content': judge_prompt}],
                format="json"
            )
            
            result = json.loads(completion['message']['content'])
            result['timestamp'] = datetime.now().isoformat()
            result['category'] = category
            
            return result
            
        except Exception as e:
            self.logger.error(f"Mistral7b judge evaluation failed: {e}")
            return {
                "score": 0, 
                "rationale": f"Local judge model call failed: {e}",
                "strengths": "Evaluation failed",
                "improvements": "Fix model connection",
                "timestamp": datetime.now().isoformat(),
                "category": category
            }
    
    def batch_evaluate_dataset(self, dataset_path: str, sample_size: int = 50) -> Dict[str, Any]:
        """Evaluate a sample of dataset examples using Mistral7b as judge"""
        
        print(f"🔍 BATCH EVALUATING DATASET: {dataset_path}")
        print("=" * 60)
        
        dataset_file = Path(dataset_path)
        if not dataset_file.exists():
            raise FileNotFoundError(f"Dataset not found: {dataset_path}")
        
        # Load dataset samples
        examples = []
        with open(dataset_file, 'r') as f:
            for i, line in enumerate(f):
                if i >= sample_size:
                    break
                examples.append(json.loads(line))
        
        print(f"📊 Evaluating {len(examples)} examples...")
        
        # Evaluate each example
        evaluations = []
        for i, example in enumerate(examples):
            print(f"⚖️  Evaluating example {i+1}/{len(examples)}")
            
            # Determine category based on metadata
            category = self._determine_evaluation_category(example)
            
            # Get instruction and output
            instruction = example.get('instruction', '')
            output = example.get('output', '')
            
            # Evaluate with Mistral7b
            evaluation = self.llm_as_judge(instruction, output, category)
            evaluation['example_index'] = i
            evaluation['example_metadata'] = example.get('meta', {})
            
            evaluations.append(evaluation)
        
        # Generate summary report
        summary = self._generate_evaluation_summary(evaluations)
        
        # Save results
        results_file = self.fine_tuning_dir / "validation/results" / f"mistral7b_evaluation_{datetime.now().strftime('%Y%m%d_%H%M%S')}.json"
        results_file.parent.mkdir(parents=True, exist_ok=True)
        
        with open(results_file, 'w') as f:
            json.dump({
                "dataset_path": str(dataset_path),
                "evaluation_summary": summary,
                "individual_evaluations": evaluations,
                "evaluation_metadata": {
                    "timestamp": datetime.now().isoformat(),
                    "sample_size": len(examples),
                    "evaluator_model": "mistral:7b"
                }
            }, f, indent=2)
        
        print(f"✅ Evaluation complete! Results saved: {results_file}")
        return summary
    
    def _determine_evaluation_category(self, example: Dict[str, Any]) -> str:
        """Determine the appropriate evaluation category for an example"""
        
        # Check metadata for role information
        meta = example.get('meta', {})
        role = meta.get('role', '')
        
        if role:
            return role
        
        # Check for methodology indicators in instruction
        instruction = example.get('instruction', '').lower()
        
        if '[methodology:' in instruction:
            if 'socratic' in instruction:
                return 'socratic_questioning'
            elif 'step-by-step' in instruction:
                return 'step_by_step_clarity'
            elif 'error analysis' in instruction:
                return 'error_analysis'
            elif 'conceptual' in instruction:
                return 'conceptual_explanation'
            else:
                return 'methodology_effectiveness'
        
        # Default to tutoring evaluation
        return 'tutoring'
    
    def _generate_evaluation_summary(self, evaluations: List[Dict[str, Any]]) -> Dict[str, Any]:
        """Generate summary statistics from evaluations"""
        
        if not evaluations:
            return {"error": "No evaluations to summarize"}
        
        # Calculate score statistics
        scores = [eval_result['score'] for eval_result in evaluations if eval_result['score'] > 0]
        
        if not scores:
            return {"error": "No valid scores found"}
        
        # Category breakdown
        category_stats = {}
        for evaluation in evaluations:
            category = evaluation['category']
            if category not in category_stats:
                category_stats[category] = {'scores': [], 'count': 0}
            
            if evaluation['score'] > 0:
                category_stats[category]['scores'].append(evaluation['score'])
            category_stats[category]['count'] += 1
        
        # Calculate averages
        for category, stats in category_stats.items():
            if stats['scores']:
                stats['average_score'] = sum(stats['scores']) / len(stats['scores'])
                stats['min_score'] = min(stats['scores'])
                stats['max_score'] = max(stats['scores'])
            else:
                stats['average_score'] = 0
                stats['min_score'] = 0
                stats['max_score'] = 0
        
        return {
            "overall_average": sum(scores) / len(scores),
            "total_evaluated": len(evaluations),
            "valid_scores": len(scores),
            "score_distribution": {
                "min": min(scores),
                "max": max(scores),
                "scores": scores
            },
            "category_breakdown": category_stats,
            "quality_assessment": self._assess_quality(sum(scores) / len(scores))
        }
    
    def _assess_quality(self, average_score: float) -> str:
        """Provide quality assessment based on average score"""
        
        if average_score >= 4.5:
            return "Excellent - Ready for production use"
        elif average_score >= 4.0:
            return "Very Good - Minor refinements needed"
        elif average_score >= 3.5:
            return "Good - Some improvements recommended"
        elif average_score >= 3.0:
            return "Fair - Significant improvements needed"
        else:
            return "Poor - Major revision required"
    
    def content_preparation_pipeline(self, raw_content: str, content_type: str) -> Dict[str, Any]:
        """Use Mistral7b to prepare and enhance educational content"""
        
        preparation_prompt = f"""You are an expert educational content developer. Your task is to enhance and prepare educational content for use in tutoring AI training.

        Content Type: {content_type}
        Raw Content: {raw_content}

        Please provide a JSON response with:
        - "enhanced_content": Improved version of the content
        - "learning_objectives": List of clear learning objectives
        - "prerequisite_knowledge": What students should know first
        - "difficulty_level": Beginner/Intermediate/Advanced
        - "teaching_strategies": Recommended approaches for this content
        - "assessment_suggestions": How to evaluate understanding
        - "visual_aids_needed": Suggestions for diagrams, charts, etc.

        Your JSON response:
        """
        
        try:
            completion = ollama.chat(
                model="mistral:7b",
                messages=[{'role': 'user', 'content': preparation_prompt}],
                format="json"
            )
            
            result = json.loads(completion['message']['content'])
            result['preparation_timestamp'] = datetime.now().isoformat()
            result['content_type'] = content_type
            
            return result
            
        except Exception as e:
            self.logger.error(f"Content preparation failed: {e}")
            return {
                "error": f"Content preparation failed: {e}",
                "raw_content": raw_content,
                "content_type": content_type
            }

def main():
    """Demonstrate Mistral7b integration for fine-tuning ecosystem"""
    
    framework = Mistral7bJudgeFramework()
    
    print("🤖 MISTRAL7B INTEGRATION FRAMEWORK")
    print("=" * 70)
    print("Capabilities:")
    print("✅ LLM-as-Judge evaluation of tutoring responses")
    print("✅ Batch dataset quality assessment")  
    print("✅ Educational content preparation and enhancement")
    print("✅ Multi-category evaluation (tutoring, methodology, personas)")
    print("✅ Comprehensive scoring and feedback generation")
    
    # Example evaluation of your balanced dataset
    print(f"\n📊 Ready to evaluate your 1,842-example balanced dataset!")
    print(f"Dataset: fine_tuning/datasets/processed/next_epoch/final_balanced_dataset.jsonl")
    print(f"🎯 This will help validate your personality integration quality")
    
    # Example content preparation
    print(f"\n🛠️  Ready for content preparation pipeline!")
    print(f"Use Mistral7b to enhance raw educational content before training")

if __name__ == "__main__":
    main()
