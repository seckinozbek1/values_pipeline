import pandas as pd
import numpy as np
import plotly.graph_objects as go

# Load scored sentences CSV
top_scored_df = pd.read_csv("../../../output/question_pipeline_output/q11_predictions/q11_predictions_filtered.csv")

q11_label = 'Q11_1'  # Label to analyze

# Filter to rows matching the Q11 label
df_q11_label = top_scored_df[top_scored_df['predicted_combined_label'] == q11_label]

# Count sentences per country-year for Q11_label
agg_scored = df_q11_label.groupby(['B_COUNTRY_ALPHA', 'A_YEAR']).agg(
    sentence_count=('predicted_combined_label', 'count')
).reset_index()

# Count total Q11 sentences per country-year (any Q11_*)
total_q11_per_country_year = top_scored_df[
    top_scored_df['predicted_combined_label'].str.startswith('Q11_')
].groupby(['B_COUNTRY_ALPHA', 'A_YEAR']).size().reset_index(name='total_q11_count')

# Merge counts and compute proportion scored per country-year
agg_scored = agg_scored.merge(total_q11_per_country_year, on=['B_COUNTRY_ALPHA', 'A_YEAR'])
agg_scored['proportion_scored'] = agg_scored['sentence_count'] / agg_scored['total_q11_count']

# Load WVS Wave 7 data
wvs_path = r"../../../output/master_code_prep_output/wvs7_full_data.csv"
wvs_df = pd.read_csv(wvs_path, low_memory=False)

# Filter WVS Q11 responses by valid country-year pairs in scored data
valid_country_years = set(zip(agg_scored['B_COUNTRY_ALPHA'], agg_scored['A_YEAR']))

wvs_q11 = wvs_df[['B_COUNTRY_ALPHA', 'A_YEAR', 'Q11', 'S018']].dropna(subset=['B_COUNTRY_ALPHA', 'A_YEAR', 'Q11', 'S018'])
wvs_q11 = wvs_q11[wvs_q11.apply(lambda row: (row['B_COUNTRY_ALPHA'], row['A_YEAR']) in valid_country_years, axis=1)]
wvs_q11['Q11'] = pd.to_numeric(wvs_q11['Q11'], errors='coerce')
wvs_q11 = wvs_q11.dropna(subset=['Q11'])

# Compute weighted proportion per country-year for Q11 = target label
target_label = int(q11_label[-1])

def weighted_proportion(group):
    """
    Calculate the weighted proportion of rows in a group matching the target label.

    The proportion is computed as the weighted count of observations where `Q11`
    equals the global `target_label`, divided by the total weight `S018`.

    Args:
        group (pandas.DataFrame): Grouped subset of the data containing columns
            'Q11' (labels) and 'S018' (weights).

    Returns:
        float: Weighted proportion of the target label, or NaN if total weight is zero.
    """
    weights = group['S018']
    label_mask = (group['Q11'] == target_label).astype(int)
    weighted_count = np.sum(weights * label_mask)
    total_weight = np.sum(weights)
    return weighted_count / total_weight if total_weight > 0 else np.nan

agg_wvs = wvs_q11.groupby(['B_COUNTRY_ALPHA', 'A_YEAR']).apply(
    lambda g: pd.Series({
        'weighted_proportion_wvs': weighted_proportion(g),
        'total_weight': g['S018'].sum()
    })
).reset_index()

# Merge scored and WVS weighted data on country-year
merged = pd.merge(
    agg_scored[['B_COUNTRY_ALPHA', 'A_YEAR', 'proportion_scored']],
    agg_wvs[['B_COUNTRY_ALPHA', 'A_YEAR', 'weighted_proportion_wvs']],
    on=['B_COUNTRY_ALPHA', 'A_YEAR']
)

merged = merged.sort_values(['B_COUNTRY_ALPHA', 'A_YEAR']).reset_index(drop=True)
labels = merged.apply(lambda row: f"{row['B_COUNTRY_ALPHA']}_{row['A_YEAR']}", axis=1)

fig = go.Figure()

# Add vertical lines connecting WVS and scored proportions per country-year
for _, row in merged.iterrows():
    fig.add_trace(go.Scatter(
        x=[f"{row['B_COUNTRY_ALPHA']}_{row['A_YEAR']}", f"{row['B_COUNTRY_ALPHA']}_{row['A_YEAR']}"],
        y=[row['weighted_proportion_wvs'], row['proportion_scored']],
        mode='lines',
        line=dict(color='gray'),
        showlegend=False,
        hoverinfo='skip'
    ))

# Points for WVS weighted proportions
fig.add_trace(go.Scatter(
    x=labels,
    y=merged['weighted_proportion_wvs'],
    mode='markers',
    name=f'WVS Weighted {q11_label}',
    marker=dict(color='blue', size=8),
    hovertemplate='%{x}<br>WVS Weighted Proportion: %{y:.2f}<extra></extra>'
))

# Points for scored sentences
fig.add_trace(go.Scatter(
    x=labels,
    y=merged['proportion_scored'],
    mode='markers',
    name=f'Scored Sentences {q11_label}',
    marker=dict(color='red', size=8),
    hovertemplate='%{x}<br>Sentence Proportion: %{y:.2f}<extra></extra>'
))

fig.update_layout(
    title=f'WVS Weighted vs Scored Sentences Proportion of {q11_label} by Country-Year',
    xaxis_title='Country-Year',
    yaxis_title='Proportion',
    yaxis=dict(range=[0, 1.1]),
    height=600,
    hovermode='x unified'
)

fig.show()

# Calculate Pearson correlation between WVS weighted proportions and scored sentence proportions
correlation = merged['weighted_proportion_wvs'].corr(merged['proportion_scored'])
print(f"Pearson correlation between WVS weighted and scored sentence proportions: {correlation:.4f}")
