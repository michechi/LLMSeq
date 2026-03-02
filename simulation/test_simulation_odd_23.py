import matplotlib.pyplot as plt
import numpy as np
import pandas as pd
import string
import random
import collections
import sys

from pathlib import Path
from sklearn.model_selection import train_test_split
from multiprocessing import Pool, cpu_count
from collections import Counter
from scipy.stats import bernoulli
from itertools import product
from typing import List, Union
from tqdm import tqdm

# # Aggiungi la directory MIMICIV al path FOR DEBUG ONLY
# root_dir = Path(__file__).parent.parent  # Sale di due livelli
# sys.path.insert(0, str(root_dir))

# For multi-ordering key test
from simulation.do_assign_outcome_pos import assign_outcome_positional, efficient_check_parallel

def rm_all():
    [globals().pop(var) for var in list(globals()) if not var.startswith('_')]

def generate_sequences(
    letters:list, n:int=10, m:int=10_000, replacement:bool=False, seed:int=None, batch_size:int=None, duplicates:bool=False
):
    """
    Generate exactly m unique sequences (rows) of length n where each event is 'Letter' + 'Digit' (A1, Z0, H4, ...).
    - If replacement=False, each *row* has no repeated letters and no repeated digits.
    - Across rows, duplicates are removed; generation continues until m unique rows are collected.
    """
    rng = np.random.default_rng(seed)
    L = np.asarray(letters, dtype='<U8')
    Llen = len(L)

    if not replacement and n > Llen:
        raise ValueError("n must be <= len(letters) when replacement=False")

    # Choose a sensible batch size (oversample a bit to reduce iterations)
    if batch_size is None:
        batch_size = min(10_000, m // 10)

    # Store unique rows via a hash set of compact string keys
    # Use a separator that won't appear in tokens (ASCII Unit Separator)
    SEP = "\x1f"
    seen = set()
    out_rows = []

    def _gen_batch(k):
        """k batch dimension"""
        if replacement:
            print("replacement!\n")
            li = rng.integers(0, Llen, size=(k, n))
        else:
            print("no replacement!\n")
            # Per-row permutations (no repeats within a row)
            l_scores = rng.random((k, Llen))
            li = np.argsort(l_scores, axis=1)[:, :n]
        seq = L[li]  # shape (k, n), dtype '<U...'
        return seq

    while len(out_rows) < m:
        need = m - len(out_rows)
        k = max(batch_size, need)  # at least batch_size to amortize costs
        seq = _gen_batch(k)        # (k, n)

        # Build vectorized keys for dedup: "A|B|..."
        keys = [SEP.join(key) for key in seq.tolist()]
        # Inefficient! (?)
        # for j in range(1, n):
        #     keys = np.char.add(np.char.add(keys, SEP), seq[:, j])

        # Filter rows not seen before
        mask_new = np.fromiter((key not in seen for key in keys), count=k, dtype=bool)
        if not mask_new.any():
            continue

        # new_keys = keys[mask_new] # Now keys it's a list not an array so this won't work
        new_keys = [key for key,to_keep in zip(keys, mask_new) if to_keep]

        out_rows+=new_keys
        for key in new_keys:
            seen.add(key)

    return out_rows

# For parallelization
def worker_generate(args):
    letters, n, m_chunk, replacement, seed = args
    return generate_sequences(letters, n, m_chunk, replacement, seed)


random.seed(959693)

n_events = 20 # More
n_seq = 5_000_000
n_0s = 100_000
n_1s = 100_000
n_tot = n_0s + n_1s
generate = True
parallel = True
cycle = False
debugging=False
rnd=False
even=True

if not rnd:
    number_csv=5

letters = list(string.ascii_uppercase)

letters_4_key = ["W", "D", "Q", "J", "X", "N"] # Added X Keep it fixed!!

c_vocab = {w:p for p,w in enumerate(letters_4_key,start=0)}

# This is sequential
if generate:
    if not parallel:
        sequences = generate_sequences(letters=letters, n=n_events, m=n_seq, replacement=True)
    else:
        # Parallel version
        n_cores = cpu_count()-1
        rng = np.random.default_rng(999)
        seeds = rng.integers(0, 2**31, size=n_cores)
        m_per_core = int(n_seq * 1.2 / n_cores)  # 20% oversample
        tasks = [(letters, n_events, m_per_core, True, seed) for seed in seeds]
        with Pool(processes=n_cores) as pool:
            results = pool.map(worker_generate, tasks)
        # Deduplicate and trim
        all_sequences = [seq for result in results for seq in result]
        sequences = list(dict.fromkeys(all_sequences))[:n_seq]

        if even:
            tasks = [(letters, n_events+1, m_per_core, True, seed+1) for seed in seeds]
            with Pool(processes=n_cores) as pool:
                results = pool.map(worker_generate, tasks)
            # Deduplicate and trim
            all_sequences = [seq for result in results for seq in result]
            odd_sequences = list(dict.fromkeys(all_sequences))[:n_seq]
            sequences+=odd_sequences # now we have both odd and even

else:
    # Load pre-generated sequences (from previous runs)
    sequences = pd.read_csv(f"data/simulation/X_test_{number_csv}.csv")["Sequences"].tolist()
    labels = pd.read_csv(f"data/simulation/y_test_{number_csv}.csv")["Outcome"].tolist()

    sequences += pd.read_csv(f"data/simulation/X_train_{number_csv}.csv")["Sequences"].tolist()
    labels += pd.read_csv(f"data/simulation/y_train_{number_csv}.csv")["Outcome"].tolist()

    sequences += pd.read_csv(f"data/simulation/X_val_{number_csv}.csv")["Sequences"].tolist()
    labels += pd.read_csv(f"data/simulation/y_val_{number_csv}.csv")["Outcome"].tolist()

n_seq = len(sequences)
set_seq = set(sequences)
n_set_seq = len(set_seq)

if n_seq != n_set_seq:
    print(f"Attention! There are {n_seq-n_set_seq} duplicates!\nRemoving them..")
    sequences = set_seq.copy()
    n_seq = n_set_seq
    del set_seq, n_set_seq
    print("Done!")

# Testing for multiple key ordering
# lags = do_lags(letters, 1234)
def extract_characters(seq:str, sep:str="\x1f") -> str:
    seq_char = "-".join([x[0] for x in seq.split(sep)])
    return(seq_char)

# Check with reality
if (not generate):
    print(pd.Series(labels).value_counts()/len(labels))

def sample_with_proportion(df, n, pi, label_col='Outcome', random_state=9550):
    """
    Sample n rows from df with specified proportion of positive class.

    Parameters:
    -----------
    df : pd.DataFrame
        Input dataframe
    n : int
        Total number of samples to return
    pi : float
        Proportion of positive class (label=1), between 0 and 1
    label_col : str
        Name of the label column
    random_state : int, optional
        Random seed for reproducibility

    Returns:
    --------
    pd.DataFrame
        Sampled dataframe with desired proportion
    """
    # Calculate number of samples per class
    n_pos = int(n * pi)
    n_neg = n - n_pos

    # Separate by class
    df_pos = df[df[label_col] == 1]
    df_neg = df[df[label_col] == 0]

    # Check if we have enough samples
    if len(df_pos) < n_pos:
        raise ValueError(f"Not enough positive samples: need {n_pos}, have {len(df_pos)}")
    if len(df_neg) < n_neg:
        raise ValueError(f"Not enough negative samples: need {n_neg}, have {len(df_neg)}")

    # Sample from each class
    sampled_pos = df_pos.sample(n=n_pos, random_state=random_state)
    sampled_neg = df_neg.sample(n=n_neg, random_state=random_state)

    # Combine and shuffle
    sampled_df = pd.concat([sampled_pos, sampled_neg], axis=0)
    sampled_df = sampled_df.sample(frac=1, random_state=random_state)  # shuffle

    return sampled_df.reset_index(drop=True)

def check_key_order_by_frequency(seq, key_letters, sep='\x1f', already_splitted=False):
    """
    Verifica che le lettere chiave rispettino un ordine di frequenza decrescente
    basato sull'ordine di prima apparizione nella sequenza.
    
    Regola:
    - Prima lettera chiave che appare → deve avere frequenza maggiore
    - Seconda lettera chiave che appare → deve avere frequenza maggiore della terza
    - Terza lettera chiave che appare → deve avere frequenza maggiore della quarta
    - etc.
    
    Se la regola è rispettata per tutte le lettere chiave, ritorna 1, altrimenti 0.
    
    Parameters:
    -----------
    seq : str or list
        La sequenza
    key_letters : list
        Lista delle lettere chiave
    
    Returns:
    --------
    int : 1 se rispetta l'ordine di frequenza, 0 altrimenti
    
    Examples:
    ---------
    seq = "A-A-A-B-B-C-D-D-D"  # A appare 3 volte, B 2 volte, C 1 volta
    key_letters = ['A', 'B', 'C', 'D']
    # Ordine di apparizione: A (pos 0), B (pos 3), C (pos 5), D (pos 6)
    # Frequenze: A=3, B=2, C=1, D=3
    # Check: A(3) > B(2)? ✓  B(2) > C(1)? ✓  C(1) > D(3)? ✗
    # Ritorna 0
    """
    
    if not already_splitted:
        seq_list = seq.split(sep)
    else:
        seq_list = seq
    
    # Trova l'ordine di prima apparizione delle lettere chiave
    first_appearance = {}
    
    for pos, letter in enumerate(seq_list):
        if letter in key_letters and letter not in first_appearance:
            first_appearance[letter] = pos
    
    # Se non ci sono lettere chiave nella sequenza
    if not first_appearance:
        return 1  # Oppure 0, dipende da come vuoi gestire questo caso
    
    # Ordina le lettere chiave per ordine di apparizione
    ordered_keys = sorted(first_appearance.keys(), key=lambda k: first_appearance[k])
    
    # Se c'è solo una lettera chiave, la condizione è automaticamente soddisfatta
    if len(ordered_keys) <= 1:
        return 1
    
    # Conta le frequenze di ogni lettera chiave
    key_counts = {key: seq_list.count(key) for key in ordered_keys}
    
    # Verifica che le frequenze siano in ordine decrescente
    for i in range(len(ordered_keys) - 1):
        current_key = ordered_keys[i]
        next_key = ordered_keys[i + 1]
        
        if key_counts[current_key] < key_counts[next_key]:
            # La regola è violata
            return 0
    
    # Tutte le verifiche sono passate
    return 1

# Versione con dettagli per debugging
def check_key_order_by_frequency_debug(seq, key_letters, sep='\x1f', already_splitted=False):
    """
    Versione con output dettagliato.
    """
    
    if not already_splitted:
        seq_list = seq.split(sep)
    else:
        seq_list = seq
    
    print(f"Sequence: {'-'.join(seq_list)}")
    print(f"Key letters to check: {key_letters}")
    print()
    
    # Trova l'ordine di prima apparizione
    first_appearance = {}
    
    for pos, letter in enumerate(seq_list):
        if letter in key_letters and letter not in first_appearance:
            first_appearance[letter] = pos
    
    if not first_appearance:
        print("No key letters found in sequence!")
        return 1
    
    # Ordina per apparizione
    ordered_keys = sorted(first_appearance.keys(), key=lambda k: first_appearance[k])
    
    print("Order of first appearance:")
    for i, key in enumerate(ordered_keys, 1):
        print(f"  {i}. Letter '{key}' first appears at position {first_appearance[key]}")
    print()
    
    # Conta frequenze
    key_counts = {key: seq_list.count(key) for key in ordered_keys}
    
    print("Frequencies:")
    for key in ordered_keys:
        print(f"  Letter '{key}': {key_counts[key]} occurrences")
    print()
    
    # Verifica ordine
    print("Checking frequency order (must be strictly decreasing):")
    all_valid = True
    
    for i in range(len(ordered_keys) - 1):
        current_key = ordered_keys[i]
        next_key = ordered_keys[i + 1]
        current_count = key_counts[current_key]
        next_count = key_counts[next_key]
        
        is_valid = current_count > next_count
        status = "✓" if is_valid else "✗"
        
        print(f"  {current_key}({current_count}) > {next_key}({next_count})? {status}")
        
        if not is_valid:
            all_valid = False
    
    result = 1 if all_valid else 0
    print(f"\nFinal result: {result}")
    return result

############ END ############

lags = 7 # csv 0
# lags = 0

# Testing for multiple key ordering
# lags = do_lags(letters, 1234)
function_2_use_4_outcome = assign_outcome_positional

if parallel:
    # Parallel:
    n_cores = cpu_count()-4
    
    check, df_2_monitor = efficient_check_parallel(
            sequences=sequences,
            c_vocab=c_vocab,
            assign_outcome_positional=function_2_use_4_outcome,
            tolerance=False,
            lags=lags,
            rnd=rnd,              #### >>>>>>>>> CHANGE HERE PARAMETER !!!
            debugging=debugging,
            min_chain_length=3,   #### >>>>>>>>> CHANGE HERE PARAMETER !!!
            n_workers=n_cores  # oppure None per usare tutti i core
        )
df_2_monitor = df_2_monitor.rename(columns={"outcome":"Outcome"})
df_odd = sample_with_proportion(df_2_monitor.loc[(df_2_monitor['odd'])], 100_000, 0.5)
df_even = sample_with_proportion(df_2_monitor.loc[~(df_2_monitor['odd'])], 100_000, 0.5)


# Create Dataset
df = pd.DataFrame({
    "Sequences":pd.concat([df_odd['seq'],df_even['seq']]),
    "Outcome":pd.concat([df_odd['Outcome'],df_even['Outcome']])
})

# df['Outcome'] = df["Sequences"].apply(lambda x: check_key_order_by_frequency(x, letters_4_key))


df_1s = df.loc[df["Outcome"]==1, ]
df_0s = df.loc[df["Outcome"]==0, ]
df_full = pd.concat([df_1s, df_0s], ignore_index=True)

# Ratio of Label:
df_full.Outcome.value_counts()/len(df_full)
# df_full = df_full.groupby('Outcome')[['Sequences', 'Outcome']].apply(lambda x: x.sample(frac=0.2))
# df_full = pd.concat([df_1s.sample(n_1s), df_0s.sample(n_0s*2)])
df_full = sample_with_proportion(df_full, n_tot, 0.5)
df_full.Outcome.value_counts()/len(df_full)
len(df_full)

# Splitting Train Val Test
# Now train_val_test split:
X, y = df_full["Sequences"], df_full["Outcome"]
X_train, X_val_test, y_train, y_val_test = train_test_split(X, y, train_size=0.80, random_state=999)
X_val, X_test, y_val, y_test = train_test_split(X_val_test, y_val_test, train_size=0.50, random_state=999)

# Uncomment just if you want to save data!
number_csv = "odd_3"
for df, name in zip([X_train, X_val, X_test, y_train, y_val, y_test], [f"X_train_{number_csv}", f"X_val_{number_csv}", f"X_test_{number_csv}", f"y_train_{number_csv}", f"y_val_{number_csv}", f"y_test_{number_csv}"]):
    df.to_csv(f"data/simulation/{name}.csv", index=False)

# GRAPHICAL STUFF
# Let's visualize bigrams
def plot_bigram_distribution(X_train, y_train, from_n=0, top_n=30):
    """
    Crea un grafico che mostra i bigrammi più discriminativi
    tra le due classi
    """

    # Funzione per estrarre bigrammi
    def extract_bigrams(seq):
        letters = seq.split('\x1f')
        return [f"{letters[i]}-{letters[i+1]}" for i in range(len(letters)-1)]

    # Conta bigrammi per classe
    bigrams_0 = Counter()
    bigrams_1 = Counter()

    for seq, label in zip(pd.DataFrame(X_train)['Sequences'], pd.DataFrame(y_train)['Outcome']):
        bigrams = extract_bigrams(seq)
        if label == 0:
            bigrams_0.update(bigrams)
        else:
            bigrams_1.update(bigrams)

    # Calcola frequenze normalizzate
    total_0 = sum(bigrams_0.values())
    total_1 = sum(bigrams_1.values())

    # Trova bigrammi più discriminativi
    all_bigrams = set(bigrams_0.keys()) | set(bigrams_1.keys())
    bigram_diff = {}

    for bg in all_bigrams:
        freq_0 = bigrams_0.get(bg, 0)
        freq_1 = bigrams_1.get(bg, 0)
        diff = abs(freq_0 - freq_1)
        bigram_diff[bg] = (freq_0, freq_1, diff)

    # Ordina per differenza e prendi top N
    top_bigrams = sorted(bigram_diff.items(), key=lambda x: x[1][2], reverse=True)[from_n:top_n]

    # Prepara dati per il grafico
    bigram_labels = [bg for bg, _ in top_bigrams]
    counts_0 = [data[0] for _, data in top_bigrams]
    counts_1 = [data[1] for _, data in top_bigrams]

    # Crea il grafico
    x = np.arange(len(bigram_labels))
    width = 0.35

    fig, ax = plt.subplots(figsize=(16, 8))
    bars1 = ax.bar(x - width/2, counts_1, width, label='Label=1 (Ordered)', alpha=0.8)
    bars0 = ax.bar(x + width/2, counts_0, width, label='Label=0 (Unordered)', alpha=0.8)

    ax.set_xlabel('Bigrams', fontsize=12)
    ax.set_ylabel('Count', fontsize=12)
    ax.set_title(f'Top {top_n} Most Discriminative Bigrams by Label', fontsize=14)
    ax.set_xticks(x)
    ax.set_xticklabels(bigram_labels, rotation=45, ha='right')
    ax.legend()
    ax.grid(axis='y', alpha=0.3)

    plt.tight_layout()
    plt.savefig('bigram_distribution.png', dpi=300, bbox_inches='tight')
    plt.show()

    # Stampa statistiche
    print(f"\nTop {min(10, top_n)} most discriminative bigrams:")
    print(f"{'Bigram':<10} {'Count(Label=0)':<15} {'Count(Label=1)':<15} {'Difference':<12}")
    print("-" * 60)
    for bg, (c0, c1, diff) in top_bigrams[:10]:
        print(f"{bg:<10} {c0:<15} {c1:<15} {diff:<12.0f}")

# Esegui
plot_bigram_distribution(X_train, y_train, from_n=1, top_n=50)

def plot_ngram_vignette(X_train, y_train, max_n=7, top_n=700):
    """
    Create a vignette (faceted) plot showing n-gram distributions from 2-grams to max_n-grams.
    Each subplot shows the top_n most discriminative n-grams.
    """

    def extract_ngrams(seq, n):
        """Extract n-grams from a sequence"""
        letters = seq.split('\x1f')
        if len(letters) < n:
            return []
        return ["-".join(letters[i:i+n]) for i in range(len(letters)-n+1)]

    # Prepare subplots
    n_grams = list(range(2, max_n + 1))
    n_plots = len(n_grams)
    n_cols = 2  # 2 columns
    n_rows = int(np.ceil(n_plots / n_cols))

    fig, axes = plt.subplots(n_rows, n_cols, figsize=(24, 6*n_rows))
    axes = axes.flatten() if n_plots > 1 else [axes]

    for idx, n in enumerate(n_grams):
        ax = axes[idx]

        # Count n-grams per class
        ngrams_0 = Counter()
        ngrams_1 = Counter()

        for seq, label in zip(pd.DataFrame(X_train)['Sequences'], pd.DataFrame(y_train)['Outcome']):
            ngrams = extract_ngrams(seq, n)
            if label == 0:
                ngrams_0.update(ngrams)
            else:
                ngrams_1.update(ngrams)

        # Find most discriminative n-grams
        all_ngrams = set(ngrams_0.keys()) | set(ngrams_1.keys())
        ngram_diff = {}

        for ng in all_ngrams:
            freq_0 = ngrams_0.get(ng, 0)
            freq_1 = ngrams_1.get(ng, 0)
            diff = abs(freq_0 - freq_1)
            ngram_diff[ng] = (freq_0, freq_1, diff)

        # Sort and take top N
        top_ngrams = sorted(ngram_diff.items(), key=lambda x: x[1][2], reverse=True)[:top_n]

        # Prepare data
        ngram_labels = [ng for ng, _ in top_ngrams]
        counts_0 = [data[0] for _, data in top_ngrams]
        counts_1 = [data[1] for _, data in top_ngrams]

        # Plot
        x = np.arange(len(ngram_labels))
        width = 0.35

        ax.bar(x - width/2, counts_1, width, label='Label=1', alpha=0.8, color='C0')
        ax.bar(x + width/2, counts_0, width, label='Label=0', alpha=0.8, color='C1')

        ngram_name = {2: 'Bigrams', 3: 'Trigrams', 4: '4-grams', 5: '5-grams', 6: '6-grams', 7: '7-grams'}
        ax.set_title(f'Top {len(ngram_labels)} {ngram_name.get(n, f"{n}-grams")}', fontsize=12, fontweight='bold')

        ax.set_xlabel(f'{ngram_name.get(n, f"{n}-grams")}', fontsize=10)
        ax.set_ylabel('Count', fontsize=10)

        # Don't show x-tick labels for top_n=100 (too crowded)
        ax.set_xticks([])

        if idx == 0:  # Legend only on first plot
            ax.legend(fontsize=10)

        ax.grid(axis='y', alpha=0.3)

        # Print top 5 for each n-gram
        print(f"\nTop 5 most discriminative {ngram_name.get(n, f'{n}-grams')}:")
        print(f"{f'{n}-gram':<30} {'Count(0)':<12} {'Count(1)':<12} {'Diff':<10}")
        print("-" * 70)
        for ng, (c0, c1, diff) in top_ngrams[:5]:
            print(f"{ng:<30} {c0:<12} {c1:<12} {diff:<10.0f}")

    # Hide unused subplots
    for j in range(n_plots, len(axes)):
        axes[j].set_visible(False)

    plt.suptitle(f'N-gram Distribution Analysis (Top {top_n} Most Discriminative)',
                 fontsize=16, fontweight='bold', y=0.995)
    plt.tight_layout()
    plt.savefig('ngram_vignette.png', dpi=300, bbox_inches='tight')
    plt.show()

# Usage
plot_ngram_vignette(X_train, y_train, max_n=7, top_n=50)