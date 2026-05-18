import argparse
import json
import os
import random

import evaluate
import numpy as np
import torch
import vllm

from eval.utils import (dynamic_import_function, generate_completions,
                        load_hf_lm_and_tokenizer, query_openai_chat_model)

encoding_templates_with_context = {
    "english": ("Answer the following question based on the information in the given passage.", "Passage:", "Question:", "Answer:"),
    "arabic": ("أجب على السؤال التالي بناءً على المعلومات في المقطع المعطى.", "المقطع:", "السؤال:", "الإجابة:"),
    "bengali": ("প্রদত্ত অধ্যায়ের তথ্যের উপর ভিত্তি করে নিম্নলিখিত প্রশ্নের উত্তর দিন।", "অধ্যায়:", "প্রশ্ন:", "উত্তর:"),
    "finnish": ("Vastaa seuraavaan kysymykseen annetun kappaleen tiedon perusteella.", "Kappale:", "Kysymys:", "Vastaus:"),
    "indonesian": ("Jawab pertanyaan berikut berdasarkan informasi di bagian yang diberikan.", "Bagian:", "Pertanyaan:", "Jawaban:"),
    "korean": ("주어진 문단의 정보에 기반하여 다음 질문에 답하십시오.", "문단:", "질문:", "답변:"),
    "russian": ("Ответьте на следующий вопрос на основе информации в данном отрывке.", "Отрывок:", "Вопрос:", "Ответ:"),
    "swahili": ("Jibu swali lifuatalo kulingana na habari kwenye kifungu kilichotolewa.", "Kifungu:", "Swali:", "Jibu:"),
    "telugu": ("ఇచ్చిన పేరాలోని సమాచారం ఆధారంగా కింది ప్రశ్నకు సమాధానం ఇవ్వండి.", "పేరా:", "ప్రశ్న:", "సమాధానం:")
}

encoding_templates_without_context = {
    "english": ("Answer the following question.", "Question:", "Answer:"),
    "arabic": ("أجب على السؤال التالي.", "السؤال:", "الإجابة:"),
    "bengali": ("নিম্নলিখিত প্রশ্নের উত্তর দিন।", "প্রশ্ন:", "উত্তর:"),
    "finnish": ("Vastaa seuraavaan kysymykseen.", "Kysymys:", "Vastaus:"),
    "indonesian": ("Jawab pertanyaan berikut.", "Pertanyaan:", "Jawaban:"),
    "korean": ("다음 질문에 답하십시오.", "질문:", "답변:"),
    "russian": ("Ответьте на следующий вопрос.", "Вопрос:", "Ответ:"),
    "swahili": ("Jibu swali lifuatalo.", "Swali:", "Jibu:"),
    "telugu": ("క్రింది ప్రశ్నకు సమాధానం ఇవ్వండి.", "ప్రశ్న:", "సమాధానం:")
}


def main(args):
    random.seed(42)

    print("Loading data...")

    test_data = []
    with open(os.path.join(args.data_dir, "tydiqa-goldp-v1.1-dev.json")) as fin:
        dev_data = json.load(fin)
        for article in dev_data["data"]:
            for paragraph in article["paragraphs"]:
                for qa in paragraph["qas"]:
                    example = {
                        "id": qa["id"],
                        "lang": qa["id"].split("-")[0],
                        "context": paragraph["context"],
                        "question": qa["question"],
                        "answers": qa["answers"]
                    }
                    test_data.append(example)
    data_languages = set([example["lang"] for example in test_data])

    print("Calculating F1, EM ...")
    metric = evaluate.load("squad")

    eval_scores = {}
    for lang in data_languages:
        lang_predictions = [{"id": example["id"], "prediction_text": "answer"}
                            for example in test_data if example["lang"] == lang]
        lang_references = []
        for example in test_data:
            if example["lang"] != lang:
                continue
            texts = [a['text'] for a in example['answers']]
            starts = [a['answer_start'] for a in example['answers']]
            lang_references.append({
                "id": example["id"],
                "answers": {"text": texts, "answer_start": starts}
            })
        eval_scores[lang] = metric.compute(
            predictions=lang_predictions, references=lang_references)

    eval_scores["average"] = {metric: np.mean(
        [scores[metric] for scores in eval_scores.values()]) for metric in ["f1", "exact_match"]}

    print("Scores:")
    print(json.dumps(eval_scores, indent=4))

    with open(os.path.join(args.save_dir, "metrics.json"), "w") as fout:
        json.dump(eval_scores, fout, indent=4)
    print("Done!")


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument(
        "--data_dir",
        type=str,
        default="data/xorqa/"
    )
    parser.add_argument(
        "--max_num_examples_per_lang",
        type=int,
        default=None,
        help="maximum number of examples per language to evaluate."
    )
    parser.add_argument(
        "--n_shot",
        type=int,
        default=1,
        help="number of examples to use for few-shot evaluation."
    )
    parser.add_argument(
        "--no_context",
        action="store_true",
        help="If given, we're evaluating a model without the gold context passage."
    )
    parser.add_argument(
        "--max_context_length",
        type=int,
        default=512,
        help="maximum number of tokens in the context passage."
    )
    parser.add_argument(
        "--save_dir",
        type=str,
        default="results/tydiqa/"
    )
    parser.add_argument(
        "--model_name_or_path",
        type=str,
        default=None,
        help="if specified, we will load the model to generate the predictions."
    )
    parser.add_argument(
        "--tokenizer_name_or_path",
        type=str,
        default=None,
        help="if specified, we will load the tokenizer from here."
    )
    parser.add_argument(
        "--use_slow_tokenizer",
        action="store_true",
        help="If given, we will use the slow tokenizer."
    )
    parser.add_argument(
        "--openai_engine",
        type=str,
        default=None,
        help="if specified, we will use the OpenAI API to generate the predictions."
    )
    parser.add_argument(
        "--eval_batch_size",
        type=int,
        default=1,
        help="batch size for evaluation."
    )
    parser.add_argument(
        "--load_in_8bit",
        action="store_true",
        help="load model in 8bit mode, which will reduce memory and speed up inference."
    )
    parser.add_argument(
        "--gptq",
        action="store_true",
        help="If given, we're evaluating a 4-bit quantized GPTQ model."
    )
    parser.add_argument(
        "--use_vllm",
        action="store_true",
        help="If given, we will use the vllm library, which will likely increase the inference throughput."
    )
    parser.add_argument(
        "--use_chat_format",
        action="store_true",
        help="If given, we will use the chat format for the prompts."
    )
    parser.add_argument(
        "--chat_formatting_function",
        type=str,
        default="eval.templates.create_prompt_with_tulu_chat_format",
        help="The function to use to create the chat format. This function will be dynamically imported. Please see examples in `eval/templates.py`."
    )
    parser.add_argument(
        "--convert_to_half",
        action="store_true",
        help="Load model in half.",
    )
    parser.add_argument(
        "--convert_to_bf16",
        action="store_true",
        help="Load model in bf16.",
    )
    parser.add_argument(
        "--eval_valid",
        action="store_true",
        help="If given, we will use gpu for inference.")
    args = parser.parse_args()
    # model_name_or_path and openai_engine cannot be both None or both not None.
    assert (args.model_name_or_path is None) != (
        args.openai_engine is None), "Either model_name_or_path or openai_engine should be specified."
    main(args)
