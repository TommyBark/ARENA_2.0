# %%
import os

os.environ["ACCELERATE_DISABLE_RICH"] = "1"
import sys
from functools import partial
import json
from typing import List, Tuple, Union, Optional, Callable, Dict
import torch as t
from torch import Tensor
from sklearn.linear_model import LinearRegression
import numpy as np
from plotly.subplots import make_subplots
import plotly.express as px
import plotly.graph_objects as go
import einops
from tqdm import tqdm
from jaxtyping import Float, Int, Bool
from pathlib import Path
import pandas as pd
import circuitsvis as cv
import webbrowser
from IPython.display import display
from transformer_lens import (
    utils,
    ActivationCache,
    HookedTransformer,
    HookedTransformerConfig,
)
from transformer_lens.hook_points import HookPoint
from transformer_lens.components import LayerNorm

# Make sure exercises are in the path
chapter = r"chapter1_transformers"
exercises_dir = Path(f"{os.getcwd().split(chapter)[0]}/{chapter}/exercises").resolve()
section_dir = exercises_dir / "part4_interp_on_algorithmic_model"
if str(exercises_dir) not in sys.path:
    sys.path.append(str(exercises_dir))

import plotly_utils
from plotly_utils import hist, bar, imshow
import part4_interp_on_algorithmic_model.tests as tests
from part4_interp_on_algorithmic_model.brackets_datasets import (
    SimpleTokenizer,
    BracketsDataset,
)

device = t.device("cuda" if t.cuda.is_available() else "cpu")

MAIN = __name__ == "__main__"

# %%
VOCAB = "()"

cfg = HookedTransformerConfig(
    n_ctx=42,
    d_model=56,
    d_head=28,
    n_heads=2,
    d_mlp=56,
    n_layers=3,
    attention_dir="bidirectional",  # defaults to "causal"
    act_fn="relu",
    d_vocab=len(VOCAB) + 3,  # plus 3 because of end and pad and start token
    d_vocab_out=2,  # 2 because we're doing binary classification
    use_attn_result=True,
    device=device,
    use_hook_tokens=True,
)

model = HookedTransformer(cfg).eval()

state_dict = t.load(section_dir / "brackets_model_state_dict.pt", map_location=device)
model.load_state_dict(state_dict)

# %%
tokenizer = SimpleTokenizer("()")

# Examples of tokenization
# (the second one applies padding, since the sequences are of different lengths)
print(tokenizer.tokenize("()"))
print(tokenizer.tokenize(["()", "()()"]))

# Dictionaries mapping indices to tokens and vice versa
print(tokenizer.i_to_t)
print(tokenizer.t_to_i)

# Examples of decoding (all padding tokens are removed)
print(tokenizer.decode(t.tensor([[0, 3, 4, 2, 1, 1]])))


# %%
def add_perma_hooks_to_mask_pad_tokens(
    model: HookedTransformer, pad_token: int
) -> HookedTransformer:
    # Hook which operates on the tokens, and stores a mask where tokens equal [pad]
    def cache_padding_tokens_mask(
        tokens: Float[Tensor, "batch seq"], hook: HookPoint
    ) -> None:
        hook.ctx["padding_tokens_mask"] = einops.rearrange(
            tokens == pad_token, "b sK -> b 1 1 sK"
        )

    # Apply masking, by referencing the mask stored in the `hook_tokens` hook context
    def apply_padding_tokens_mask(
        attn_scores: Float[Tensor, "batch head seq_Q seq_K"],
        hook: HookPoint,
    ) -> None:
        attn_scores.masked_fill_(
            model.hook_dict["hook_tokens"].ctx["padding_tokens_mask"], -1e5
        )
        if hook.layer() == model.cfg.n_layers - 1:
            del model.hook_dict["hook_tokens"].ctx["padding_tokens_mask"]

    # Add these hooks as permanent hooks (i.e. they aren't removed after functions like run_with_hooks)
    for name, hook in model.hook_dict.items():
        if name == "hook_tokens":
            hook.add_perma_hook(cache_padding_tokens_mask)
        elif name.endswith("attn_scores"):
            hook.add_perma_hook(apply_padding_tokens_mask)

    return model


model.reset_hooks(including_permanent=True)
model = add_perma_hooks_to_mask_pad_tokens(model, tokenizer.PAD_TOKEN)
# %%
N_SAMPLES = 5000
with open(section_dir / "brackets_data.json") as f:
    data_tuples: List[Tuple[str, bool]] = json.load(f)
    print(f"loaded {len(data_tuples)} examples")
assert isinstance(data_tuples, list)
data_tuples = data_tuples[:N_SAMPLES]
data = BracketsDataset(data_tuples).to(device)
data_mini = BracketsDataset(data_tuples[:100]).to(device)
# %%
hist(
    [len(x) for x, _ in data_tuples],
    nbins=data.seq_length,
    title="Sequence lengths of brackets in dataset",
    labels={"x": "Seq len"},
)

# %%
# Define and tokenize examples
examples = [
    "()()",
    "(())",
    "))((",
    "()",
    "((()()()()))",
    "(()()()(()(())()",
    "()(()(((())())()))",
]
labels = [True, True, False, True, True, False, True]
toks = tokenizer.tokenize(examples)

# Get output logits for the 0th sequence position (i.e. the [start] token)
logits = model(toks)[:, 0]

# Get the probabilities via softmax, then get the balanced probability (which is the second element)
prob_balanced = logits.softmax(-1)[:, 1]

# Display output
print(
    "Model confidence:\n"
    + "\n".join(
        [
            f"{ex:18} : {prob:<8.4%} : label={int(label)}"
            for ex, prob, label in zip(examples, prob_balanced, labels)
        ]
    )
)


# %%
def run_model_on_data(
    model: HookedTransformer, data: BracketsDataset, batch_size: int = 200
) -> Float[Tensor, "batch 2"]:
    """Return probability that each example is balanced"""
    all_logits = []
    for i in tqdm(range(0, len(data.strs), batch_size)):
        toks = data.toks[i : i + batch_size]
        logits = model(toks)[:, 0]
        all_logits.append(logits)
    all_logits = t.cat(all_logits)
    assert all_logits.shape == (len(data), 2)
    return all_logits


test_set = data
n_correct = (
    run_model_on_data(model, test_set).argmax(-1).bool() == test_set.isbal
).sum()
print(f"\nModel got {n_correct} out of {len(data)} training examples correct!")
# %%


def bracket_classifier(s: str) -> bool:
    balance = 0
    for c in s:
        if balance < 0:
            return False
        if c == "(":
            balance += 1
        if c == ")":
            balance -= 1
    return balance == 0


for parens, expected in zip(examples, labels):
    actual = bracket_classifier(parens)
    assert expected == actual, f"{parens}: expected {expected} got {actual}"
print("is_balanced_forloop ok!")


# %%
def is_balanced_vectorized(tokens: Float[Tensor, "seq_len"]) -> bool:
    """
    Return True if the parens are balanced.

    tokens is a vector which has start/pad/end indices (0/1/2) as well as left/right brackets (3/4)
    """

    table = t.tensor([0, 0, 0, 1, -1])
    stripped = table[tokens]

    cum = t.cumsum(stripped, -1)
    if cum.min() < 0:
        return False

    return cum[-1] == 0


is_balanced_vectorized(t.tensor([1, 2, 3, 4, 3, 4, 0, 1]))

# %%
for tokens, expected in zip(tokenizer.tokenize(examples), labels):
    actual = is_balanced_vectorized(tokens)
    assert expected == actual, f"{tokens}: expected {expected} got {actual}"
print("is_balanced_vectorized ok!")


# %%
def get_post_final_ln_dir(model: HookedTransformer) -> Float[Tensor, "d_model"]:
    """
    Returns the direction in which final_ln_output[0, :] should point to maximize P(unbalanced)
    """
    return model.W_U[:, 0] - model.W_U[:, 1]


tests.test_get_post_final_ln_dir(get_post_final_ln_dir, model)


# %%
def get_activations(
    model: HookedTransformer,
    toks: Int[Tensor, "batch seq"],
    names: Union[str, List[str]],
) -> Union[t.Tensor, ActivationCache]:
    """
    Uses hooks to return activations from the model.

    If names is a string, returns the activations for that hook name.
    If names is a list of strings, returns a dictionary mapping hook names to tensors of activations.
    """
    names_list = [names] if isinstance(names, str) else names
    _, cache = model.run_with_cache(
        toks,
        return_type=None,
        names_filter=lambda name: name in names_list,
    )

    return cache[names] if isinstance(names, str) else cache


def LN_hook_names(layernorm: LayerNorm) -> Tuple[str, str]:
    """
    Returns the names of the hooks immediately before and after a given layernorm.
    e.g. LN_hook_names(model.ln_final) returns ["blocks.2.hook_resid_post", "ln_final.hook_normalized"]
    """
    if layernorm.name == "ln_final":
        input_hook_name = utils.get_act_name("resid_post", 2)
        output_hook_name = "ln_final.hook_normalized"
    else:
        layer, ln = layernorm.name.split(".")[1:]
        input_hook_name = utils.get_act_name(
            "resid_pre" if ln == "ln1" else "resid_mid", layer
        )
        output_hook_name = utils.get_act_name("normalized", layer, ln)

    return input_hook_name, output_hook_name


pre_final_ln_name, post_final_ln_name = LN_hook_names(model.ln_final)
print(pre_final_ln_name, post_final_ln_name)


# %%
def get_ln_fit(
    model: HookedTransformer,
    data: BracketsDataset,
    layernorm: LayerNorm,
    seq_pos: Optional[int] = None,
) -> Tuple[LinearRegression, float]:
    """
    if seq_pos is None, find best fit aggregated over all sequence positions. Otherwise, fit only for given seq_pos.

    Returns: A tuple of a (fitted) sklearn LinearRegression object and the r^2 of the fit
    """
    input_hook_name, output_hook_name = LN_hook_names(layernorm)
    input_act = get_activations(model, data.toks, input_hook_name)
    output_act = get_activations(model, data.toks, output_hook_name)
    if seq_pos is None:
        input = einops.rearrange(
            input_act, "batch seq_pos d_model -> (batch seq_pos) d_model"
        )
        output = einops.rearrange(
            output_act, "batch seq_pos d_model -> (batch seq_pos) d_model"
        )
    else:
        input = input_act[:, seq_pos, :]
        output = output_act[:, seq_pos, :]
    lin_model = LinearRegression()
    lin_model.fit(input, output)
    return lin_model, lin_model.score(input, output)


# L_final - (seq_len, seq_len)

# tests.test_get_ln_fit(get_ln_fit, model, data_mini)

(final_ln_fit_1, r2) = get_ln_fit(model, data, layernorm=model.ln_final, seq_pos=0)
print(f"r^2 for LN_final, at sequence position 0: {r2:.4f}")

(final_ln_fit_2, r2) = get_ln_fit(
    model, data, layernorm=model.blocks[1].ln1, seq_pos=None
)
print(f"r^2 for LN1, layer 1, over all sequence positions: {r2:.4f}")


# %%
def get_pre_final_ln_dir(
    model: HookedTransformer, data: BracketsDataset
) -> Float[Tensor, "d_model"]:
    """
    Returns the direction in residual stream (pre ln_final, at sequence position 0) which
    most points in the direction of making an unbalanced classification.
    """
    return t.from_numpy(
        get_ln_fit(model, data, layernorm=model.ln_final, seq_pos=0)[0].coef_.T
    ) @ get_post_final_ln_dir(model)


tests.test_get_pre_final_ln_dir(get_pre_final_ln_dir, model, data_mini)
# %%


def get_out_by_components(
    model: HookedTransformer, data: BracketsDataset
) -> Float[Tensor, "component batch seq_pos emb"]:
    """
    Computes a tensor of shape [10, dataset_size, seq_pos, emb] representing the output of the model's components when run on the data.
    The first dimension is  [embeddings, head 0.0, head 0.1, mlp 0, head 1.0, head 1.1, mlp 1, head 2.0, head 2.1, mlp 2].
    The embeddings are the sum of token and positional embeddings.
    """
    # SOLUTION
    embedding_hook_names = ["hook_embed", "hook_pos_embed"]
    head_hook_names = [
        utils.get_act_name("result", layer) for layer in range(model.cfg.n_layers)
    ]
    mlp_hook_names = [
        utils.get_act_name("mlp_out", layer) for layer in range(model.cfg.n_layers)
    ]

    all_hook_names = embedding_hook_names + head_hook_names + mlp_hook_names
    activations = get_activations(model, data.toks, all_hook_names)

    out = (activations["hook_embed"] + activations["hook_pos_embed"]).unsqueeze(0)

    for head_hook_name, mlp_hook_name in zip(head_hook_names, mlp_hook_names):
        out = t.concat(
            [
                out,
                einops.rearrange(
                    activations[head_hook_name],
                    "batch seq heads emb -> heads batch seq emb",
                ),
                activations[mlp_hook_name].unsqueeze(0),
            ]
        )

    return out


# %%
biases = model.b_O.sum(0)
out_by_components = get_out_by_components(model, data)
summed_terms = out_by_components.sum(dim=0) + biases

final_ln_input_name, final_ln_output_name = LN_hook_names(model.ln_final)
final_ln_input = get_activations(model, data.toks, final_ln_input_name)

t.testing.assert_close(summed_terms, final_ln_input)
print("Tests passed!")
# %%

out_components = out_by_components[:, :, 0, :]
pre_final_ln_dir = get_pre_final_ln_dir(model, data)
out_by_component_in_unbalanced_dir = einops.einsum(
    out_components,
    pre_final_ln_dir,
    "component batch d_model, d_model -> component batch",
)

mean_balanced_components = einops.einsum(
    out_components,
    pre_final_ln_dir,
    "component batch d_model, d_model -> component batch",
)[:, data.isbal].mean(axis=1, keepdim=True)

out_by_component_in_unbalanced_dir -= mean_balanced_components
tests.test_out_by_component_in_unbalanced_dir(
    out_by_component_in_unbalanced_dir, model, data
)

plotly_utils.hists_per_comp(
    out_by_component_in_unbalanced_dir, data, xaxis_range=[-10, 20]
)


# %%
def is_balanced_vectorized_return_both(
    toks: Float[Tensor, "batch seq"]
) -> Tuple[Bool[Tensor, "batch"], Bool[Tensor, "batch"]]:
    # SOLUTION
    table = t.tensor([0, 0, 0, 1, -1]).to(device)
    change = table[toks.to(device)].flip(-1)
    altitude = t.cumsum(change, -1)
    total_elevation_failure = altitude[:, -1] != 0
    negative_failure = altitude.max(-1).values > 0
    return total_elevation_failure, negative_failure
