import torch

from transformers import PreTrainedTokenizerFast
from transformers import GPT2LMHeadModel


tokenizer = PreTrainedTokenizerFast.from_pretrained(
    "skt/kogpt2-base-v2",
    bos_token="</s>",
    eos_token="</s>",
    unk_token="<unk>",
    pad_token="<pad>",
    mask_token="<mask>",
)

token = tokenizer.tokenize("안녕하세요. 한국어 GPT-2 입니다.😤:)l^o")
print(token)

model = GPT2LMHeadModel.from_pretrained("skt/kogpt2-base-v2")

text = "근육이 커지기 위해서는"
input_ids = tokenizer.encode(text, return_tensors="pt")
gen_ids = model.generate(
    input_ids,
    max_length=128,
    repetition_penalty=2.0,
    pad_token_id=tokenizer.pad_token_id,
    eos_token_id=tokenizer.eos_token_id,
    bos_token_id=tokenizer.bos_token_id,
    use_cache=True,
)

generated = tokenizer.decode(gen_ids[0])
print(generated)
