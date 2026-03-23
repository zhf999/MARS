import pickle
import argparse
from model_generation import ModelGeneration
from perturbation import Perturbation
from toxic_data import *
from utils import compute_text_perplexity,evaluate_toxicity, evaluate_model_ppl
from tqdm.auto import tqdm

def evaluate(model_nickname="mistral-7b", dataset="datasetChal", test_size=100, p_0=1e-6, start_layer=0, end_layer=32, perturbated_label="all",repeat=1):
    llm_gen = ModelGeneration(model_nickname)
    rtp = prepare_RTP(data_path=f"ToxicData/{dataset}",size=test_size)
    llm_gen.set_perturbation(None)

    clfr = pickle.load(open(f"pickles/{model_nickname}_clfr.pkl", "rb"))
    pert = Perturbation(clfr, 
                        target_probability=p_0, 
                        perturbed_layers=[i for i in range(start_layer, end_layer)],
                        perturbated_label=perturbated_label,
                        repeat=repeat)
    llm_gen.set_perturbation(pert)

    perturb_completions = []
    for prompt in tqdm(rtp, desc=f"Generating with perturbation, p_0={p_0},start layer={start_layer},end layer={end_layer}"):
        completion = llm_gen.generate(prompt)
        perturb_completions.append(completion['completion'])

    print("Perturbed completions:",perturb_completions)

    ppls, mean_ppl = compute_text_perplexity(perturb_completions)

    print("mean ppl:",mean_ppl)
    

    pickle.dump(
        (perturb_completions, mean_ppl),
        open(f"pickles/{model_nickname}_{dataset.split(".")[0]}_{perturbated_label}_p{p_0}.pkl","wb")
            )

if __name__ == '__main__':
    parser = argparse.ArgumentParser()
    parser.add_argument('--model', '-m', type=str, default='mistral-7b')
    parser.add_argument('--p0', '-p', type=float, default=1e-6)
    parser.add_argument('--test_size', '-n', type=int, default=100)
    parser.add_argument('--start_layer', '-s', type=int, default=0)
    parser.add_argument('--end_layer', '-e', type=int, default=32)
    parser.add_argument("--dataset", '-d', type=str, default="datasetChal.jsonl")
    parser.add_argument("--label",'-l', type=str, default="all", choices=JIGSAW_COMPONENTS + ["all"])
    parser.add_argument("--repeat","-r", type=int, default=1)
    args = parser.parse_args()

    model_nickname = args.model
    p_0 = args.p0
    test_size = args.test_size
    start_layer = args.start_layer
    end_layer = args.end_layer
    dataset = args.dataset
    perturbated_label = args.label
    repeat = args.repeat

    evaluate(model_nickname, dataset, test_size, p_0, start_layer, end_layer, perturbated_label,repeat=repeat)


