code = """import json
import sqlite3
import os

# Get NYSE ARCA ETFs
nyse_arca_path = locals()['var_functions.query_db:0']
with open(nyse_arca_path, 'r') as f:
    nyse_arca_etfs = json.load(f)

nyse_arca_symbols = [etf['Symbol'] for etf in nyse_arca_etfs]

# Connect to the DuckDB database
# Note: The actual connection details will be handled by the query_db tool
# We'll use query_db from within this script conceptually

# We'll need to query each ETF table to check if it had Adj Close > 200 in 2015
# Let's do this systematically

result_summary = {
    "total_etfs_checked": len(nyse_arca_symbols),
    "etfs_above_200": [],
    "count": 0
}

# Store the result for return
print("__RESULT__:")
print(json.dumps(result_summary))"""

env_args = {'var_functions.query_db:0': 'file_storage/functions.query_db:0.json', 'var_functions.execute_python:10': {'count': 1435, 'preview': ['AAAU', 'AADR', 'ABEQ', 'ACSG', 'ACWF', 'AFK', 'AFLG', 'AFMC', 'AFSM', 'AFTY']}, 'var_functions.list_db:12': 'file_storage/functions.list_db:12.json', 'var_functions.execute_python:14': {'total_nyse_arca_etfs': 1435, 'etfs_with_data': 1435, 'etfs_without_data': 0, 'existing_sample': ['AAAU', 'AADR', 'ABEQ', 'ACSG', 'ACWF', 'AFK', 'AFLG', 'AFMC', 'AFSM', 'AFTY'], 'missing_sample': []}, 'var_functions.query_db:18': []}

exec(code, env_args)
