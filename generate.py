import torch
import torch.nn as nn
from torchtyping import TensorType

class Solution:
    def generate(self, model, new_chars: int, context: TensorType[int],
                 context_length: int, int_to_char: dict) -> str:

        result = ""

        generator = torch.manual_seed(0)
        initial_state = generator.get_state()

        for i in range(new_chars):
            context = context[:, -context_length:]

            with torch.no_grad():
                logits = model(context)          # (1, T, vocab_size)
                last_logits = logits[:, -1, :]   # (1, vocab_size)
                probs = torch.softmax(last_logits, dim=-1)

                next_token = torch.multinomial(
                    probs, 1, generator=generator
                )                               # (1, 1)

            generator.set_state(initial_state)

            context = torch.cat(
                [context, next_token], dim=1
            )                                   # (1, T + 1)

            result += int_to_char[next_token.item()]

        return result