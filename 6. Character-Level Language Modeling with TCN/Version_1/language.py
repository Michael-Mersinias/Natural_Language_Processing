from .models import LanguageModel, AdjacentLanguageModel, Bigram, load_model
from . import utils


def log_likelihood(model: LanguageModel, some_text: str):
    """
    Your code here

    Evaluate the log-likelihood of a given string.

    Hint: utils.one_hot might come in handy

    :param model: A LanguageModel
    :param some_text:
    :return: float
    """
    all_logprob = model.predict_all(some_text)
    one_hot = utils.one_hot(some_text)
    return (all_logprob[:, :-1] * one_hot).sum()
    # raise NotImplementedError('compute_log_likelihood')


def sample_random(model: LanguageModel, max_length: int = 100):
    """
    Your code here.

    Sample a random sentence from the language model.
    Terminate once you reach a period '.'

    :param model: A LanguageModel
    :param max_length: The maximum sentence length
    :return: A string
    """
    from torch.distributions import Categorical
    s = ''
    while len(s) == 0 or s[-1] != '.':
        if len(s) >= max_length:
            break
        s += utils.vocab[Categorical(logits=model.predict_next(s)).sample()]
    return s


class TopNHeap:
    """
    A heap that keeps the top N elements around
    h = TopNHeap(2)
    h.add(1)
    h.add(2)
    h.add(3)
    h.add(0)
    print(h.elements)
    > [2,3]

    """
    def __init__(self, N):
        self.elements = []
        self.N = N

    def add(self, e):
        from heapq import heappush, heapreplace
        if len(self.elements) < self.N:
            heappush(self.elements, e)
        elif self.elements[0] < e:
            heapreplace(self.elements, e)


def beam_search(model: LanguageModel, beam_size: int, n_results: int = 10, max_length: int = 100, average_log_likelihood: bool = False):
    """
    Your code here

    Use beam search for find the highest likelihood generations, such that:
      * No two returned sentences are the same
      * the `log_likelihood` of each returned sentence is as large as possible

    :param model: A LanguageModel
    :param beam_size: The size of the beam in beam search (number of sentences to keep around)
    :param n_results: The number of results to return
    :param max_length: The maximum sentence length
    :param average_log_likelihood: Pick the best beams according to the average log-likelihood, not the sum
                                   This option favors longer strings.
    :return: A list of strings of size beam_size
    """
    results = TopNHeap(n_results)
    beam = TopNHeap(beam_size)
    beam.add((0, ''))
    for it in range(max_length):
        new_beam = TopNHeap(beam_size)
        for l, s in beam.elements:
            ll = model.predict_next(s)
            for i, c in enumerate(utils.vocab):
                if c == '.':
                    norm = 1. / len(s+c) if average_log_likelihood else 1
                    results.add(((l+float(ll[i])) * norm, s+c))
                else:
                    new_beam.add((l+float(ll[i]), s+c))
        beam = new_beam

    return [s for l, s in results.elements]


if __name__ == "__main__":
    """
      Some test code.
    """
    from argparse import ArgumentParser

    parser = ArgumentParser()
    parser.add_argument('-m', '--model', choices=['Adjacent', 'Bigram', 'TCN'], default='Adjacent')
    args = parser.parse_args()

    lm = AdjacentLanguageModel() if args.model == 'Adjacent' else (load_model() if args.model == 'TCN' else Bigram())

    for s in ['abcdefg', 'abcgdef', 'abcbabc', '.abcdef', 'fedcba.']:
        print(s, float(log_likelihood(lm, s)))
    print()

    for i in range(10):
        s = sample_random(lm)
        print(s, float(log_likelihood(lm, s)) / len(s))
    print()

    for s in beam_search(lm, 100):
        print(s, float(log_likelihood(lm, s)) / len(s))
    print()

    for s in beam_search(lm, 100, average_log_likelihood=True):
        print(s, float(log_likelihood(lm, s)) / len(s))
