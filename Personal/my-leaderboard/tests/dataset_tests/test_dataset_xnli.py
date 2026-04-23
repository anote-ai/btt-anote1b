"""
Comprehensive tests for XNLI - Cross-Lingual Natural Language Inference

After you generate test cases with ChatGPT and paste them into
tests/fixtures/multilingual/xnli_comprehensive.py,
uncomment the tests below and run:

    pytest tests/dataset_tests/test_dataset_xnli.py -v
"""
import pytest
from tests.fixtures.multilingual.xnli_comprehensive import (
    ALL_TEST_CASES,
    STANDARD_CASES,
    EDGE_CASES,
    ADVERSARIAL_CASES
)
from evaluators import TextClassificationEvaluator


class TestXNLIComprehensive:
    """Comprehensive test suite for XNLI dataset"""
    
    @pytest.fixture
    def evaluator(self):
        return TextClassificationEvaluator()
    
    def test_perfect_predictions_all_cases(self, evaluator):
        """Test perfect accuracy on all languages"""
        predictions = [
            {"id": item["id"], "prediction": item["answer"]}
            for item in ALL_TEST_CASES
        ]
        
        scores = evaluator.evaluate(ALL_TEST_CASES, predictions)
        
        assert scores["accuracy"] == pytest.approx(1.0)
        assert scores["f1"] == pytest.approx(1.0)
        print(f"✅ Perfect accuracy on {len(ALL_TEST_CASES)} XNLI test cases (10 languages)")
    
    def test_label_distribution_three_way(self):
        """Verify balanced distribution of entailment/contradiction/neutral"""
        labels = [item["answer"] for item in STANDARD_CASES]
        label_counts = {
            "entailment": labels.count("entailment"),
            "contradiction": labels.count("contradiction"),
            "neutral": labels.count("neutral"),
        }
        
        total = len(STANDARD_CASES)
        print(f"\nLabel distribution across {total} cases:")
        for label, count in label_counts.items():
            print(f"  {label}: {count} ({count/total*100:.1f}%)")
        
        # All 3 classes should be present
        assert all(count > 0 for count in label_counts.values())
        
        # Should be roughly balanced (20-40% each, allowing some variance)
        for count in label_counts.values():
            assert 0.2 <= count / total <= 0.4
    
    def test_per_language_coverage(self):
        """Verify all 10 languages are represented"""
        expected_langs = ["en", "es", "fr", "de", "zh", "ar", "ru", "hi", "vi", "th"]
        
        languages_in_data = set(item["language"] for item in ALL_TEST_CASES)
        
        print(f"\nLanguages in test data: {sorted(languages_in_data)}")
        
        # All expected languages should be present
        for lang in expected_langs:
            assert lang in languages_in_data, f"Missing language: {lang}"
        
        # Count per language
        lang_counts = {}
        for item in STANDARD_CASES:
            lang = item["language"]
            lang_counts[lang] = lang_counts.get(lang, 0) + 1
        
        print("\nCases per language:")
        for lang, count in sorted(lang_counts.items()):
            print(f"  {lang}: {count}")
    
    def test_per_language_accuracy(self, evaluator):
        """Test accuracy can be computed per language"""
        if not STANDARD_CASES:
            pytest.skip("No standard cases yet")
        
        # Get all languages
        languages = list(set(item["language"] for item in STANDARD_CASES))
        
        for lang in languages[:3]:  # Test first 3 languages
            lang_cases = [c for c in STANDARD_CASES if c["language"] == lang]
            predictions = [
                {"id": item["id"], "prediction": item["answer"]}
                for item in lang_cases
            ]
            
            scores = evaluator.evaluate(lang_cases, predictions)
            assert scores["accuracy"] == pytest.approx(1.0)
            print(f"✅ Language '{lang}': 1.0 accuracy on {len(lang_cases)} cases")
    
    def test_cross_lingual_consistency(self, evaluator):
        """Test that same logical relationship gets same label across languages"""
        # Example: "A man is playing guitar → A person is making music" should be
        # entailment in all languages
        
        # This is more of a validation check than evaluator test
        # Find parallel examples (same ID base across languages)
        base_ids = set()
        for item in STANDARD_CASES:
            # Extract base ID (e.g., "en_101" → "101")
            if "_" in item["id"]:
                base = item["id"].split("_", 1)[1]
                base_ids.add(base)
        
        # Check if we have parallel examples
        if base_ids:
            print(f"\n✅ Found {len(base_ids)} parallel example sets across languages")
    
    def test_entailment_subset_relationship(self, evaluator):
        """Test understanding of entailment (subset relationship)"""
        ground_truth = [
            {
                "id": "1",
                "question": "Premise: A cat is sleeping on a couch. Hypothesis: An animal is resting.",
                "answer": "entailment",
                "language": "en"
            }
        ]
        predictions = [{"id": "1", "prediction": "entailment"}]
        
        scores = evaluator.evaluate(ground_truth, predictions)
        assert scores["accuracy"] == pytest.approx(1.0)
    
    def test_contradiction_opposite(self, evaluator):
        """Test understanding of contradiction"""
        ground_truth = [
            {
                "id": "1",
                "question": "Premise: The room is full. Hypothesis: The room is empty.",
                "answer": "contradiction",
                "language": "en"
            }
        ]
        predictions = [{"id": "1", "prediction": "contradiction"}]
        
        scores = evaluator.evaluate(ground_truth, predictions)
        assert scores["accuracy"] == pytest.approx(1.0)
    
    def test_neutral_insufficient_info(self, evaluator):
        """Test understanding of neutral (can't determine)"""
        ground_truth = [
            {
                "id": "1",
                "question": "Premise: A person is walking. Hypothesis: The person is happy.",
                "answer": "neutral",
                "language": "en"
            }
        ]
        predictions = [{"id": "1", "prediction": "neutral"}]
        
        scores = evaluator.evaluate(ground_truth, predictions)
        assert scores["accuracy"] == pytest.approx(1.0)
    
    def test_adversarial_negation(self, evaluator):
        """Test negation handling in NLI"""
        if not ADVERSARIAL_CASES:
            pytest.skip("No adversarial cases yet")
        
        negation_cases = [
            c for c in ADVERSARIAL_CASES
            if any(word in c["question"].lower() for word in ["not", "no", "never", "nobody", "nothing"])
        ]
        
        if negation_cases:
            predictions = [
                {"id": item["id"], "prediction": item["answer"]}
                for item in negation_cases
            ]
            
            scores = evaluator.evaluate(negation_cases, predictions)
            assert scores["accuracy"] == pytest.approx(1.0)
            print(f"✅ Correctly evaluated {len(negation_cases)} negation cases")

